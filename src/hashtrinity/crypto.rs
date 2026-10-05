//! # hashtrinity-crypto — the standard hashes as the hashtrinity fold
//!
//! Every primitive is the ONE fold (`Song/HashCrypto.lean :: md`): the compression round is the
//! trinity **merge**, the hash is the **fold** of it over the padded blocks. `hmac` is the nested
//! fold, `pbkdf2` the iterated fold, `hkdf` extract-then-expand. Output is **bit-identical** to
//! FIPS 180-4 / RFC 2104 / RFC 8018 / RFC 5869, so it drops into TLS/JWT/ed25519/x509 unchanged.
//! The compression round is the only parameter — SHA-512 (next) is the same fold, wider.
//!
//! **Zero dependencies outside `hashtrinity`** (whose `hex` masquerade replaces the `hex` crate).
#![forbid(unsafe_code)]

use crate::hashtrinity::hex::ToHex;

/// Cryptographically-secure random bytes, read directly from the kernel CSPRNG — the one place
/// this crate touches the OS for randomness (salts, nonces, key generation), shared rather than
/// duplicated per-module (`age.rs` had its own private copy before this). `pub`, not `pub(crate)`,
/// since sibling crates (`hashtrinity-webauthn`'s challenge generation) need it too — one RNG read
/// site for the whole ecosystem, not a re-duplicated `/dev/urandom` open per crate.
pub fn rand_bytes(n: usize) -> Vec<u8> {
    use std::io::Read;
    let mut f = std::fs::File::open("/dev/urandom").expect("open /dev/urandom");
    let mut b = vec![0u8; n];
    f.read_exact(&mut b).expect("read /dev/urandom");
    b
}

mod ed25519 {
    //! Ed25519 (RFC 8032) — the **group law is the merge**, scalar-mul is the **fold**, sign/verify are
    //! our SHA-512 fold + the group ops. Gated on the RFC 8032 test vectors. Zero-dep (field + curve
    //! implemented here; hashing via this crate's `sha512`). This is what supplies iroh's `EndpointId`
    //! (an ed25519 raw public key, RFC 7250/8410) — same keys, same signatures, verified against the standard.
    #![allow(clippy::needless_range_loop)]

    use crate::hashtrinity::crypto::sha512;

    // ── Field GF(2^255 - 19), radix 2^51 (Fe = [u64;5]) ───────────────────────────────────────────────
    type Fe = [u64; 5];
    const M51: u64 = (1u64 << 51) - 1;
    const TWO_P: Fe = [
        0xFFFFFFFFFFFDA,
        0xFFFFFFFFFFFFE,
        0xFFFFFFFFFFFFE,
        0xFFFFFFFFFFFFE,
        0xFFFFFFFFFFFFE,
    ];

    fn fe0() -> Fe {
        [0; 5]
    }
    fn fe1() -> Fe {
        [1, 0, 0, 0, 0]
    }
    fn fe_small(n: u64) -> Fe {
        [n, 0, 0, 0, 0]
    }

    fn carry(mut a: Fe) -> Fe {
        a[1] += a[0] >> 51;
        a[0] &= M51;
        a[2] += a[1] >> 51;
        a[1] &= M51;
        a[3] += a[2] >> 51;
        a[2] &= M51;
        a[4] += a[3] >> 51;
        a[3] &= M51;
        a[0] += 19 * (a[4] >> 51);
        a[4] &= M51;
        a
    }
    fn fe_add(a: &Fe, b: &Fe) -> Fe {
        carry([
            a[0] + b[0],
            a[1] + b[1],
            a[2] + b[2],
            a[3] + b[3],
            a[4] + b[4],
        ])
    }
    fn fe_sub(a: &Fe, b: &Fe) -> Fe {
        carry([
            a[0] + TWO_P[0] - b[0],
            a[1] + TWO_P[1] - b[1],
            a[2] + TWO_P[2] - b[2],
            a[3] + TWO_P[3] - b[3],
            a[4] + TWO_P[4] - b[4],
        ])
    }
    fn fe_reduce128(h: [u128; 5]) -> Fe {
        let mut c: u128;
        let l0;
        let l1;
        let l2;
        let l3;
        let l4;
        c = h[0] >> 51;
        l0 = (h[0] as u64) & M51;
        let h1 = h[1] + c;
        c = h1 >> 51;
        l1 = (h1 as u64) & M51;
        let h2 = h[2] + c;
        c = h2 >> 51;
        l2 = (h2 as u64) & M51;
        let h3 = h[3] + c;
        c = h3 >> 51;
        l3 = (h3 as u64) & M51;
        let h4 = h[4] + c;
        c = h4 >> 51;
        l4 = (h4 as u64) & M51;
        let mut r = [l0 + 19 * (c as u64), l1, l2, l3, l4];
        r[1] += r[0] >> 51;
        r[0] &= M51;
        r
    }
    fn fe_mul(a: &Fe, b: &Fe) -> Fe {
        let m = |x: u64, y: u64| -> u128 { (x as u128) * (y as u128) };
        fe_reduce128([
            m(a[0], b[0]) + 19 * (m(a[1], b[4]) + m(a[2], b[3]) + m(a[3], b[2]) + m(a[4], b[1])),
            m(a[0], b[1]) + m(a[1], b[0]) + 19 * (m(a[2], b[4]) + m(a[3], b[3]) + m(a[4], b[2])),
            m(a[0], b[2]) + m(a[1], b[1]) + m(a[2], b[0]) + 19 * (m(a[3], b[4]) + m(a[4], b[3])),
            m(a[0], b[3]) + m(a[1], b[2]) + m(a[2], b[1]) + m(a[3], b[0]) + 19 * m(a[4], b[4]),
            m(a[0], b[4]) + m(a[1], b[3]) + m(a[2], b[2]) + m(a[3], b[1]) + m(a[4], b[0]),
        ])
    }
    fn fe_sq(a: &Fe) -> Fe {
        fe_mul(a, a)
    }
    fn fe_neg(a: &Fe) -> Fe {
        fe_sub(&fe0(), a)
    }
    fn fe_pow(base: &Fe, exp: &[u8; 32]) -> Fe {
        let mut r = fe1();
        for i in (0..256).rev() {
            r = fe_sq(&r);
            if (exp[i / 8] >> (i % 8)) & 1 == 1 {
                r = fe_mul(&r, base);
            }
        }
        r
    }
    const P_MINUS_2: [u8; 32] = {
        let mut a = [0xFFu8; 32];
        a[0] = 0xEB;
        a[31] = 0x7F;
        a
    };
    const P_MINUS_5_8: [u8; 32] = {
        let mut a = [0xFFu8; 32];
        a[0] = 0xFD;
        a[31] = 0x0F;
        a
    }; // (p-5)/8
    const P_MINUS_1_4: [u8; 32] = {
        let mut a = [0xFFu8; 32];
        a[0] = 0xFB;
        a[31] = 0x1F;
        a
    }; // (p-1)/4
    fn fe_inv(a: &Fe) -> Fe {
        fe_pow(a, &P_MINUS_2)
    }

    fn fe_frombytes(s: &[u8; 32]) -> Fe {
        let l = |i: usize| -> u64 {
            u64::from_le_bytes([
                s[i],
                s[i + 1],
                s[i + 2],
                s[i + 3],
                s[i + 4],
                s[i + 5],
                s[i + 6],
                s[i + 7],
            ])
        };
        [
            l(0) & M51,
            (l(6) >> 3) & M51,
            (l(12) >> 6) & M51,
            (l(19) >> 1) & M51,
            (l(24) >> 12) & M51,
        ]
    }
    fn fe_tobytes(h: &Fe) -> [u8; 32] {
        let mut t = carry(carry(*h));
        let mut q = (t[0] + 19) >> 51;
        q = (t[1] + q) >> 51;
        q = (t[2] + q) >> 51;
        q = (t[3] + q) >> 51;
        q = (t[4] + q) >> 51;
        t[0] += 19 * q;
        t[1] += t[0] >> 51;
        t[0] &= M51;
        t[2] += t[1] >> 51;
        t[1] &= M51;
        t[3] += t[2] >> 51;
        t[2] &= M51;
        t[4] += t[3] >> 51;
        t[3] &= M51;
        t[4] &= M51;
        let mut s = [0u8; 32];
        s[0] = t[0] as u8;
        s[1] = (t[0] >> 8) as u8;
        s[2] = (t[0] >> 16) as u8;
        s[3] = (t[0] >> 24) as u8;
        s[4] = (t[0] >> 32) as u8;
        s[5] = (t[0] >> 40) as u8;
        s[6] = ((t[0] >> 48) | (t[1] << 3)) as u8;
        s[7] = (t[1] >> 5) as u8;
        s[8] = (t[1] >> 13) as u8;
        s[9] = (t[1] >> 21) as u8;
        s[10] = (t[1] >> 29) as u8;
        s[11] = (t[1] >> 37) as u8;
        s[12] = ((t[1] >> 45) | (t[2] << 6)) as u8;
        s[13] = (t[2] >> 2) as u8;
        s[14] = (t[2] >> 10) as u8;
        s[15] = (t[2] >> 18) as u8;
        s[16] = (t[2] >> 26) as u8;
        s[17] = (t[2] >> 34) as u8;
        s[18] = (t[2] >> 42) as u8;
        s[19] = ((t[2] >> 50) | (t[3] << 1)) as u8;
        s[20] = (t[3] >> 7) as u8;
        s[21] = (t[3] >> 15) as u8;
        s[22] = (t[3] >> 23) as u8;
        s[23] = (t[3] >> 31) as u8;
        s[24] = (t[3] >> 39) as u8;
        s[25] = ((t[3] >> 47) | (t[4] << 4)) as u8;
        s[26] = (t[4] >> 4) as u8;
        s[27] = (t[4] >> 12) as u8;
        s[28] = (t[4] >> 20) as u8;
        s[29] = (t[4] >> 28) as u8;
        s[30] = (t[4] >> 36) as u8;
        s[31] = (t[4] >> 44) as u8;
        s
    }
    fn fe_eq(a: &Fe, b: &Fe) -> bool {
        fe_tobytes(a) == fe_tobytes(b)
    }
    fn fe_is_odd(a: &Fe) -> bool {
        fe_tobytes(a)[0] & 1 == 1
    }

    // ── The curve constant d = -121665/121666, and 2d ────────────────────────────────────────────────
    fn d_const() -> Fe {
        fe_mul(&fe_neg(&fe_small(121665)), &fe_inv(&fe_small(121666)))
    }
    fn d2_const() -> Fe {
        let d = d_const();
        fe_add(&d, &d)
    }
    fn sqrtm1() -> Fe {
        fe_pow(&fe_small(2), &P_MINUS_1_4)
    } // sqrt(-1)

    // ── Edwards point (extended coords X,Y,Z,T), the GROUP — merge = addition ─────────────────────────
    #[derive(Clone, Copy)]
    struct Ge {
        x: Fe,
        y: Fe,
        z: Fe,
        t: Fe,
    }
    fn ge_identity() -> Ge {
        Ge {
            x: fe0(),
            y: fe1(),
            z: fe1(),
            t: fe0(),
        }
    }

    /// THE GROUP MERGE — complete twisted-Edwards (a=-1) addition. `⊕` is commutative & associative.
    fn ge_add(p: &Ge, q: &Ge) -> Ge {
        let a = fe_mul(&fe_sub(&p.y, &p.x), &fe_sub(&q.y, &q.x));
        let b = fe_mul(&fe_add(&p.y, &p.x), &fe_add(&q.y, &q.x));
        let c = fe_mul(&fe_mul(&p.t, &d2_const()), &q.t);
        let dd = fe_add(&fe_mul(&p.z, &q.z), &fe_mul(&p.z, &q.z)); // 2 * Z1 * Z2
        let e = fe_sub(&b, &a);
        let f = fe_sub(&dd, &c);
        let g = fe_add(&dd, &c);
        let h = fe_add(&b, &a);
        Ge {
            x: fe_mul(&e, &f),
            y: fe_mul(&g, &h),
            t: fe_mul(&e, &h),
            z: fe_mul(&f, &g),
        }
    }
    fn ge_neg(p: &Ge) -> Ge {
        Ge {
            x: fe_neg(&p.x),
            y: p.y,
            z: p.z,
            t: fe_neg(&p.t),
        }
    }

    /// SCALAR MUL — the FOLD: n·P = repeated ⊕ (double-and-add over the 256-bit scalar).
    fn ge_scalarmul(scalar: &[u8; 32], p: &Ge) -> Ge {
        let mut r = ge_identity();
        for i in (0..256).rev() {
            r = ge_add(&r, &r);
            if (scalar[i / 8] >> (i % 8)) & 1 == 1 {
                r = ge_add(&r, p);
            }
        }
        r
    }
    // ── THE O(1) CLOSURE for fixed-base mul: the doubling recurrence `Pᵢ₊₁=2Pᵢ` closed-formed to `2ⁱB`,
    //    precomputed ONCE (the streaming law — certify the rest state once). Then `r·B` = a CONSTANT
    //    64-add fold over the comb table, NO doublings, scalar-value-independent. `T[k][d] = d·16ᵏ·B`. ──
    fn build_base_table() -> Vec<[Ge; 16]> {
        let mut table: Vec<[Ge; 16]> = Vec::with_capacity(64);
        let mut cur = base(); // 16^k · B
        for _ in 0..64 {
            let mut row = [ge_identity(); 16];
            row[1] = cur;
            for d in 2..16 {
                row[d] = ge_add(&row[d - 1], &cur);
            }
            table.push(row);
            for _ in 0..4 {
                cur = ge_add(&cur, &cur);
            } // ×16 for the next window
        }
        table
    }
    fn base_table() -> &'static Vec<[Ge; 16]> {
        static T: std::sync::OnceLock<Vec<[Ge; 16]>> = std::sync::OnceLock::new();
        T.get_or_init(build_base_table)
    }
    /// Constant-time nibble equality → all-ones mask iff equal (no branch on the secret).
    #[inline]
    fn ct_eq(a: u64, b: u64) -> u64 {
        let x = a ^ b;
        (((x | x.wrapping_neg()) >> 63) & 1).wrapping_sub(1)
    }
    /// Constant-time conditional move of one field element (mask = 0 or all-ones).
    #[inline]
    fn fe_cmov(dst: &mut Fe, src: &Fe, mask: u64) {
        for i in 0..5 {
            dst[i] ^= mask & (dst[i] ^ src[i]);
        }
    }
    #[inline]
    fn ge_cmov(dst: &mut Ge, src: &Ge, mask: u64) {
        fe_cmov(&mut dst.x, &src.x, mask);
        fe_cmov(&mut dst.y, &src.y, mask);
        fe_cmov(&mut dst.z, &src.z, mask);
        fe_cmov(&mut dst.t, &src.t, mask);
    }
    /// Fixed-base scalar mul via the comb table — 64 adds, no doublings, constant work. CONSTANT-TIME:
    /// the secret nibble selects its table entry by scanning ALL 16 and masking (no secret-indexed load),
    /// so the memory-access pattern is scalar-independent — the signing-secret timing leak is closed.
    fn ge_scalarmul_base(scalar: &[u8; 32]) -> Ge {
        let table = base_table();
        let mut r = ge_identity();
        for k in 0..64 {
            let byte = scalar[k / 2];
            let nib = (if k % 2 == 0 { byte & 0xf } else { byte >> 4 }) as u64; // secret
            let mut sel = ge_identity();
            for d in 0..16u64 {
                ge_cmov(&mut sel, &table[k][d as usize], ct_eq(d, nib));
            } // scan all, mask-select
            r = ge_add(&r, &sel);
        }
        r
    }
    fn ge_tobytes(p: &Ge) -> [u8; 32] {
        let zi = fe_inv(&p.z);
        let x = fe_mul(&p.x, &zi);
        let y = fe_mul(&p.y, &zi);
        let mut s = fe_tobytes(&y);
        s[31] |= (fe_is_odd(&x) as u8) << 7;
        s
    }
    /// Decompress a 32-byte point (recover x from y via the curve equation + sqrt). None if not on curve.
    fn ge_frombytes(s: &[u8; 32]) -> Option<Ge> {
        let y = fe_frombytes(s);
        let y2 = fe_sq(&y);
        let u = fe_sub(&y2, &fe1()); // y^2 - 1
        let v = fe_add(&fe_mul(&d_const(), &y2), &fe1()); // d*y^2 + 1
                                                          // x = u*v^3 * (u*v^7)^((p-5)/8)
        let v3 = fe_mul(&fe_sq(&v), &v);
        let v7 = fe_mul(&fe_sq(&v3), &v);
        let mut x = fe_mul(&fe_mul(&u, &v3), &fe_pow(&fe_mul(&u, &v7), &P_MINUS_5_8));
        let vx2 = fe_mul(&v, &fe_sq(&x));
        if !fe_eq(&vx2, &u) {
            if fe_eq(&vx2, &fe_neg(&u)) {
                x = fe_mul(&x, &sqrtm1());
            } else {
                return None;
            }
        }
        if fe_is_odd(&x) != ((s[31] >> 7) & 1 == 1) {
            x = fe_neg(&x);
        }
        Some(Ge {
            t: fe_mul(&x, &y),
            x,
            y,
            z: fe1(),
        })
    }
    /// The base point B (decoded from its compressed encoding).
    fn base() -> Ge {
        let mut b = [0x66u8; 32];
        b[0] = 0x58;
        ge_frombytes(&b).unwrap()
    }

    // ── Scalar arithmetic mod L (group order) — long division, correct-by-construction ────────────────
    const L: [u64; 4] = [
        0x5812631a5cf5d3ed,
        0x14def9dea2f79cd6,
        0x0000000000000000,
        0x1000000000000000,
    ];
    fn ge_u256(a: &[u64; 4], b: &[u64; 4]) -> bool {
        for i in (0..4).rev() {
            if a[i] != b[i] {
                return a[i] > b[i];
            }
        }
        true
    }
    fn sub_u256(a: &mut [u64; 4], b: &[u64; 4]) {
        let mut borrow = 0i128;
        for i in 0..4 {
            let v = a[i] as i128 - b[i] as i128 - borrow;
            if v < 0 {
                a[i] = (v + (1i128 << 64)) as u64;
                borrow = 1;
            } else {
                a[i] = v as u64;
                borrow = 0;
            }
        }
    }
    /// Reduce a little-endian byte string (≤64 bytes) mod L → 32 LE bytes.
    fn sc_reduce(bytes: &[u8]) -> [u8; 32] {
        let mut rem = [0u64; 4];
        for i in (0..bytes.len() * 8).rev() {
            let bit = (bytes[i / 8] >> (i % 8)) & 1;
            let mut c = bit as u64;
            for limb in rem.iter_mut() {
                let nc = *limb >> 63;
                *limb = (*limb << 1) | c;
                c = nc;
            }
            if ge_u256(&rem, &L) {
                sub_u256(&mut rem, &L);
            }
        }
        let mut o = [0u8; 32];
        for i in 0..4 {
            o[i * 8..i * 8 + 8].copy_from_slice(&rem[i].to_le_bytes());
        }
        o
    }
    /// (a*b + c) mod L.
    fn sc_muladd(a: &[u8; 32], b: &[u8; 32], c: &[u8; 32]) -> [u8; 32] {
        let ld = |s: &[u8; 32]| -> [u64; 4] {
            let mut r = [0u64; 4];
            for i in 0..4 {
                r[i] = u64::from_le_bytes(s[i * 8..i * 8 + 8].try_into().unwrap());
            }
            r
        };
        let (al, bl) = (ld(a), ld(b));
        let mut p = [0u64; 8];
        for i in 0..4 {
            let mut cr: u128 = 0;
            for j in 0..4 {
                let t = (al[i] as u128) * (bl[j] as u128) + p[i + j] as u128 + cr;
                p[i + j] = t as u64;
                cr = t >> 64;
            }
            let mut k = i + 4;
            while cr != 0 && k < 8 {
                let t = p[k] as u128 + cr;
                p[k] = t as u64;
                cr = t >> 64;
                k += 1;
            }
        }
        let mut buf = [0u8; 64];
        for k in 0..8 {
            buf[k * 8..k * 8 + 8].copy_from_slice(&p[k].to_le_bytes());
        }
        let mut cr = 0u16;
        for k in 0..32 {
            let v = buf[k] as u16 + c[k] as u16 + cr;
            buf[k] = v as u8;
            cr = v >> 8;
        }
        for k in 32..64 {
            if cr == 0 {
                break;
            }
            let v = buf[k] as u16 + cr;
            buf[k] = v as u8;
            cr = v >> 8;
        }
        sc_reduce(&buf)
    }

    // ── RFC 8032 keygen / sign / verify ───────────────────────────────────────────────────────────────
    fn clamp(h: &[u8]) -> [u8; 32] {
        let mut a = [0u8; 32];
        a.copy_from_slice(&h[0..32]);
        a[0] &= 248;
        a[31] &= 127;
        a[31] |= 64;
        a
    }
    /// Public key from a 32-byte secret: `A = a·B` — a fold over the base point.
    pub fn ed25519_pubkey(sk: &[u8; 32]) -> [u8; 32] {
        let h = sha512(sk);
        ge_tobytes(&ge_scalarmul_base(&clamp(&h)))
    }
    /// Sign `msg` (RFC 8032). Returns the 64-byte signature `R‖S`.
    pub fn ed25519_sign(sk: &[u8; 32], msg: &[u8]) -> [u8; 64] {
        let h = sha512(sk);
        let a = clamp(&h);
        let pk = ge_tobytes(&ge_scalarmul_base(&a));
        let mut pre = Vec::from(&h[32..64]);
        pre.extend_from_slice(msg);
        let r = sc_reduce(&sha512(&pre));
        let rp = ge_tobytes(&ge_scalarmul_base(&r));
        let mut km = Vec::from(&rp[..]);
        km.extend_from_slice(&pk);
        km.extend_from_slice(msg);
        let k = sc_reduce(&sha512(&km));
        let s = sc_muladd(&k, &a, &r); // (k*a + r) mod L
        let mut sig = [0u8; 64];
        sig[..32].copy_from_slice(&rp);
        sig[32..].copy_from_slice(&s);
        sig
    }
    /// Verify a 64-byte signature over `msg` for public key `pk` (RFC 8032). This is iroh's peer-signature check.
    pub fn ed25519_verify(pk: &[u8; 32], msg: &[u8], sig: &[u8; 64]) -> bool {
        let a = match ge_frombytes(pk) {
            Some(a) => a,
            None => return false,
        };
        let mut rp = [0u8; 32];
        rp.copy_from_slice(&sig[..32]);
        let mut s = [0u8; 32];
        s.copy_from_slice(&sig[32..]);
        let mut km = Vec::from(&rp[..]);
        km.extend_from_slice(pk);
        km.extend_from_slice(msg);
        let k = sc_reduce(&sha512(&km));
        // check [S]B == R + [k]A   ⟺   [S]B + [k](-A) == R
        let check = ge_add(&ge_scalarmul_base(&s), &ge_scalarmul(&k, &ge_neg(&a)));
        ge_tobytes(&check) == rp
    }

    /// Baseline for the benchmark: signing with plain double-and-add (`r·B` the O(n) fold, no comb).
    #[doc(hidden)]
    pub fn ed25519_sign_daa(sk: &[u8; 32], msg: &[u8]) -> [u8; 64] {
        let h = sha512(sk);
        let a = clamp(&h);
        let pk = ge_tobytes(&ge_scalarmul(&a, &base()));
        let mut pre = Vec::from(&h[32..64]);
        pre.extend_from_slice(msg);
        let r = sc_reduce(&sha512(&pre));
        let rp = ge_tobytes(&ge_scalarmul(&r, &base()));
        let mut km = Vec::from(&rp[..]);
        km.extend_from_slice(&pk);
        km.extend_from_slice(msg);
        let k = sc_reduce(&sha512(&km));
        let s = sc_muladd(&k, &a, &r);
        let mut sig = [0u8; 64];
        sig[..32].copy_from_slice(&rp);
        sig[32..].copy_from_slice(&s);
        sig
    }

    /// X25519 (RFC 7748) — the Montgomery ladder on Curve25519, the TLS 1.3 key exchange. Reuses the
    /// same field GF(2²⁵⁵−19). x-only differential add-and-double; scalar clamped per the RFC.
    pub fn x25519(scalar: &[u8; 32], u: &[u8; 32]) -> [u8; 32] {
        let mut k = *scalar;
        k[0] &= 248;
        k[31] &= 127;
        k[31] |= 64;
        let x1 = fe_frombytes(u);
        let (mut x2, mut z2, mut x3, mut z3) = (fe1(), fe0(), x1, fe1());
        let mut swap = 0u8;
        for t in (0..255).rev() {
            let kt = (k[t / 8] >> (t % 8)) & 1;
            swap ^= kt;
            if swap == 1 {
                core::mem::swap(&mut x2, &mut x3);
                core::mem::swap(&mut z2, &mut z3);
            }
            swap = kt;
            let a = fe_add(&x2, &z2);
            let aa = fe_sq(&a);
            let b = fe_sub(&x2, &z2);
            let bb = fe_sq(&b);
            let e = fe_sub(&aa, &bb);
            let c = fe_add(&x3, &z3);
            let d = fe_sub(&x3, &z3);
            let da = fe_mul(&d, &a);
            let cb = fe_mul(&c, &b);
            x3 = fe_sq(&fe_add(&da, &cb));
            z3 = fe_mul(&x1, &fe_sq(&fe_sub(&da, &cb)));
            x2 = fe_mul(&aa, &bb);
            z2 = fe_mul(&e, &fe_add(&aa, &fe_mul(&fe_small(121665), &e)));
        }
        if swap == 1 {
            core::mem::swap(&mut x2, &mut x3);
            core::mem::swap(&mut z2, &mut z3);
        }
        fe_tobytes(&fe_mul(&x2, &fe_inv(&z2)))
    }

    #[cfg(test)]
    mod x25519_tests {
        use super::x25519;

        fn hex_to_32(s: &str) -> [u8; 32] {
            let mut out = [0u8; 32];
            for i in 0..32 {
                out[i] = u8::from_str_radix(&s[i * 2..i * 2 + 2], 16).unwrap();
            }
            out
        }

        const BASEPOINT: [u8; 32] = {
            let mut b = [0u8; 32];
            b[0] = 9;
            b
        };

        /// Known-answer tests — scalar * basepoint, cross-checked against Python's
        /// `cryptography` library (an independent, audited X25519 implementation),
        /// not hand-transcribed from a source that turned out unreliable to eyeball.
        #[test]
        fn basepoint_scalar_mult_matches_independent_implementation() {
            let cases: [(&str, &str); 3] = [
                (
                    "e8540095fb715e26b6ab0ec8b3719a1db17ed4bc104da119a56c73550adf395a"
                        .get(..64)
                        .unwrap(),
                    "8d6e37048cedea40c86db647d38c2cc5bdaf7c2cbba363e76b0f8b17a8d58475"
                        .get(..64)
                        .unwrap(),
                ),
                (
                    "d8ef61cc51408903e974e2e4c3f0b1f0509c27bee89db421a869e0651c9f6763"
                        .get(..64)
                        .unwrap(),
                    "0cb0eb7ca93d3f3a29c86bbdb4fa8ade6921189ec32215c1c2486a2f6b369b56"
                        .get(..64)
                        .unwrap(),
                ),
                (
                    "9054eb432dc4d26a9522de8559dd9db8092465e023fec3790f53dea644e15656"
                        .get(..64)
                        .unwrap(),
                    "e3e496f887849f30a0de0e90a512b971191f221bf8899c69182d9b2f1202a14f"
                        .get(..64)
                        .unwrap(),
                ),
            ];
            for (scalar_hex, expected_pub_hex) in cases {
                let scalar = hex_to_32(scalar_hex);
                let expected = hex_to_32(expected_pub_hex);
                let actual = x25519(&scalar, &BASEPOINT);
                assert_eq!(actual, expected, "scalar {scalar_hex}");
            }
        }

        /// The Diffie-Hellman commutativity property: x25519(a, x25519(b, base)) ==
        /// x25519(b, x25519(a, base)). This only holds if the Montgomery ladder is
        /// mathematically correct — a genuine correctness check, not a weaker one
        /// than a known-answer test.
        #[test]
        fn dh_agreement_is_commutative() {
            let scalar_a = hex_to_32(
                "2824b7975a6c5ad68def8c0842c65ca6381f78822cc3070a8623525b352ab263"
                    .get(..64)
                    .unwrap(),
            );
            let scalar_b = hex_to_32(
                "78dbcc07619a8fc3dbd0aa0e4027f1f3ce81f0f39e1b09a71a4ba3d9fa9a757b"
                    .get(..64)
                    .unwrap(),
            );
            let pub_a = x25519(&scalar_a, &BASEPOINT);
            let pub_b = x25519(&scalar_b, &BASEPOINT);
            let shared_ab = x25519(&scalar_a, &pub_b);
            let shared_ba = x25519(&scalar_b, &pub_a);
            assert_eq!(shared_ab, shared_ba);
            let expected_pub_a = hex_to_32(
                "e7a2a5285aa923f6f5edb64ac15273980d45e4668a12daf3da0bd149c2617240"
                    .get(..64)
                    .unwrap(),
            );
            let expected_pub_b = hex_to_32(
                "ca44091156d99643ae95f1f0919a0b9d59ae4f139c7256822096db05bbd1e63d"
                    .get(..64)
                    .unwrap(),
            );
            let expected_shared = hex_to_32(
                "e3051bee7df5ba786c55f062c9a3d41184a4bbef37f1cf58f00e50a7b064f31e"
                    .get(..64)
                    .unwrap(),
            );
            assert_eq!(pub_a, expected_pub_a);
            assert_eq!(pub_b, expected_pub_b);
            assert_eq!(shared_ab, expected_shared);
        }

        /// Fresh random keypairs each run (not just the two fixed vectors above) — the
        /// commutativity property must hold for arbitrary scalars, not just these two.
        #[test]
        fn dh_agreement_holds_for_random_scalars() {
            for seed in 0u8..8 {
                let mut scalar_a = [0u8; 32];
                let mut scalar_b = [0u8; 32];
                for i in 0..32 {
                    scalar_a[i] = seed.wrapping_mul(31).wrapping_add(i as u8);
                    scalar_b[i] = seed.wrapping_mul(53).wrapping_add(i as u8 * 7);
                }
                let pub_a = x25519(&scalar_a, &BASEPOINT);
                let pub_b = x25519(&scalar_b, &BASEPOINT);
                assert_eq!(x25519(&scalar_a, &pub_b), x25519(&scalar_b, &pub_a));
            }
        }
    }

    /// A masquerade of the `ed25519-compact` crate's object API (`KeyPair`/`PublicKey`/`SecretKey`/
    /// `Signature`/`Noise`/`Error`) over the plain functions above. Private keys round-trip through the
    /// real RFC 8410 `OneAsymmetricKey` PKCS8 DER shape (reusing `certgen`'s encoder + `x509`'s TLV
    /// walker — the same DER tools that already issue/parse real x509 certs), so it's genuinely
    /// interoperable, not just self-consistent. `Noise` (an optional extra-randomness countermeasure in
    /// the real crate, not required by RFC 8032) is accepted for API-shape compatibility and ignored —
    /// deterministic Ed25519 signing is exactly what RFC 8032 specifies.
    pub mod ed25519_compact {
        use crate::hashtrinity::crypto::certgen::{algid_ed25519, der_int, seq, tlv};
        use crate::hashtrinity::crypto::rand_bytes;
        use crate::hashtrinity::crypto::x509::{der_children, der_tlv};

        #[derive(Debug)]
        pub struct Error(pub(crate) &'static str);
        impl core::fmt::Display for Error {
            fn fmt(&self, f: &mut core::fmt::Formatter<'_>) -> core::fmt::Result {
                write!(f, "ed25519_compact::Error: {}", self.0)
            }
        }
        impl std::error::Error for Error {}

        #[derive(Clone, Copy)]
        pub struct PublicKey([u8; 32]);
        impl PublicKey {
            pub fn as_slice(&self) -> &[u8] {
                &self.0
            }
            pub fn from_slice(b: &[u8]) -> Result<Self, Error> {
                if b.len() != 32 {
                    return Err(Error("public key must be 32 bytes"));
                }
                let mut a = [0u8; 32];
                a.copy_from_slice(b);
                Ok(Self(a))
            }
            pub fn verify(&self, msg: impl AsRef<[u8]>, sig: &Signature) -> Result<(), Error> {
                if super::ed25519_verify(&self.0, msg.as_ref(), &sig.0) {
                    Ok(())
                } else {
                    Err(Error("signature verification failed"))
                }
            }
        }

        #[derive(Clone, Copy)]
        pub struct SecretKey([u8; 32]);
        impl SecretKey {
            /// RFC 8410 `OneAsymmetricKey`: `SEQUENCE { INTEGER 0, AlgorithmIdentifier{ed25519}, OCTET STRING(OCTET STRING(seed)) }`.
            pub fn to_der(&self) -> Vec<u8> {
                let curve_private_key = tlv(0x04, &self.0); // inner OCTET STRING wraps the raw seed
                seq(&[
                    der_int(&[0]),
                    algid_ed25519(),
                    tlv(0x04, &curve_private_key),
                ])
            }
            pub fn from_der(d: &[u8]) -> Result<Self, Error> {
                let (outer_tag, ocs, oce, _) = der_tlv(d, 0).ok_or(Error("malformed PKCS8 DER"))?;
                if outer_tag != 0x30 {
                    return Err(Error("expected SEQUENCE"));
                }
                let children = der_children(d, ocs, oce);
                let (tag, cs, ce) = *children.get(2).ok_or(Error("missing privateKey field"))?;
                if tag != 0x04 {
                    return Err(Error("expected OCTET STRING"));
                }
                let (inner_tag, ics, ice, _) =
                    der_tlv(d, cs).ok_or(Error("malformed CurvePrivateKey"))?;
                if inner_tag != 0x04 || ice - ics != 32 || ice > ce {
                    return Err(Error("expected 32-byte seed"));
                }
                let mut seed = [0u8; 32];
                seed.copy_from_slice(&d[ics..ice]);
                Ok(Self(seed))
            }
            pub fn public_key(&self) -> PublicKey {
                PublicKey(super::ed25519_pubkey(&self.0))
            }
            pub fn sign(&self, msg: impl AsRef<[u8]>, _noise: Option<Noise>) -> Signature {
                Signature(super::ed25519_sign(&self.0, msg.as_ref()))
            }
        }

        pub struct Noise;
        impl Noise {
            pub fn generate() -> Self {
                Noise
            }
        }

        pub struct Signature([u8; 64]);
        impl Signature {
            pub fn from_slice(b: &[u8]) -> Result<Self, Error> {
                if b.len() != 64 {
                    return Err(Error("signature must be 64 bytes"));
                }
                let mut a = [0u8; 64];
                a.copy_from_slice(b);
                Ok(Self(a))
            }
            pub fn to_vec(&self) -> Vec<u8> {
                self.0.to_vec()
            }
        }
        impl AsRef<[u8]> for Signature {
            fn as_ref(&self) -> &[u8] {
                &self.0
            }
        }

        pub struct KeyPair {
            pub pk: PublicKey,
            pub sk: SecretKey,
        }
        impl KeyPair {
            pub fn generate() -> Self {
                let mut seed = [0u8; 32];
                seed.copy_from_slice(&rand_bytes(32));
                let sk = SecretKey(seed);
                let pk = sk.public_key();
                Self { pk, sk }
            }
        }

        #[cfg(test)]
        mod tests {
            use super::*;

            #[test]
            fn keypair_sign_verify_round_trips() {
                let kp = KeyPair::generate();
                let msg = b"sanguine";
                let sig = kp.sk.sign(msg, Some(Noise::generate()));
                assert!(kp.pk.verify(msg, &sig).is_ok());
            }

            #[test]
            fn secret_key_der_round_trips() {
                let kp = KeyPair::generate();
                let der = kp.sk.to_der();
                let restored = SecretKey::from_der(&der).unwrap();
                assert_eq!(restored.public_key().as_slice(), kp.pk.as_slice());
            }

            #[test]
            fn public_key_and_signature_slice_round_trip() {
                let kp = KeyPair::generate();
                let pk2 = PublicKey::from_slice(kp.pk.as_slice()).unwrap();
                let sig = kp.sk.sign(b"msg", None);
                let sig2 = Signature::from_slice(&sig.to_vec()).unwrap();
                assert!(pk2.verify(b"msg", &sig2).is_ok());
            }

            #[test]
            fn tampered_signature_rejected() {
                let kp = KeyPair::generate();
                let sig = kp.sk.sign(b"msg", None);
                let mut bytes = sig.to_vec();
                bytes[0] ^= 1;
                let bad = Signature::from_slice(&bytes).unwrap();
                assert!(kp.pk.verify(b"msg", &bad).is_err());
            }
        }
    }
}
pub use ed25519::ed25519_compact;
pub use ed25519::{ed25519_pubkey, ed25519_sign, ed25519_sign_daa, ed25519_verify, x25519};
mod ecdsa {
    //! ECDSA / NIST P-256 (FIPS 186-4) — the **group law is the merge** at the NIST curve; verify is the
    //! same one-cell friction check as ed25519 (`ThreatModel.secure_decided_at_one_cell`): a bad
    //! signature convicts. This is the FIPS-approved signature the real x509/TLS world signs with.
    //! Gated on RFC 6979's P-256 test vector. Zero-dep outside `hashtrinity` (arithmetic here, hash ours).
    #![allow(clippy::needless_range_loop)]

    type U = [u64; 4]; // 256-bit, little-endian limbs

    // P-256 domain (big-endian) → LE limbs, transcribed from FIPS 186-4 / SEC 2.
    const P: U = [
        0xffffffffffffffff,
        0x00000000ffffffff,
        0x0000000000000000,
        0xffffffff00000001,
    ];
    const N: U = [
        0xf3b9cac2fc632551,
        0xbce6faada7179e84,
        0xffffffffffffffff,
        0xffffffff00000000,
    ];
    const GX: U = [
        0xf4a13945d898c296,
        0x77037d812deb33a0,
        0xf8bce6e563a440f2,
        0x6b17d1f2e12c4247,
    ];
    const GY: U = [
        0xcbb6406837bf51f5,
        0x2bce33576b315ece,
        0x8ee7eb4a7c0f9e16,
        0x4fe342e2fe1a7f9b,
    ];

    fn from_be(b: &[u8]) -> U {
        let mut r = [0u64; 4];
        for i in 0..4 {
            r[i] = u64::from_be_bytes(b[24 - i * 8..32 - i * 8].try_into().unwrap());
        }
        r
    }
    fn is_zero(a: &U) -> bool {
        a == &[0, 0, 0, 0]
    }
    fn ge5(a: &[u64; 5], m: &[u64; 5]) -> bool {
        for i in (0..5).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }
    fn sub5(a: &mut [u64; 5], m: &[u64; 5]) {
        let mut br = 0i128;
        for i in 0..5 {
            let v = a[i] as i128 - m[i] as i128 - br;
            if v < 0 {
                a[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                a[i] = v as u64;
                br = 0;
            }
        }
    }
    fn ge4(a: &U, m: &U) -> bool {
        for i in (0..4).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }

    /// 256×256 → 512-bit product.
    fn mul512(a: &U, b: &U) -> [u64; 8] {
        let mut p = [0u64; 8];
        for i in 0..4 {
            let mut cr = 0u128;
            for j in 0..4 {
                let t = a[i] as u128 * b[j] as u128 + p[i + j] as u128 + cr;
                p[i + j] = t as u64;
                cr = t >> 64;
            }
            let mut k = i + 4;
            while cr != 0 && k < 8 {
                let t = p[k] as u128 + cr;
                p[k] = t as u64;
                cr = t >> 64;
                k += 1;
            }
        }
        p
    }
    /// Reduce a 512-bit value mod `m` (binary long division — correct, modulus-generic).
    fn mod_gen(x: &[u64; 8], m: &U) -> U {
        let m5 = [m[0], m[1], m[2], m[3], 0];
        let mut rem = [0u64; 5];
        for i in (0..512).rev() {
            let bit = (x[i / 64] >> (i % 64)) & 1;
            let mut c = bit;
            for l in rem.iter_mut() {
                let nc = *l >> 63;
                *l = (*l << 1) | c;
                c = nc;
            }
            if ge5(&rem, &m5) {
                sub5(&mut rem, &m5);
            }
        }
        [rem[0], rem[1], rem[2], rem[3]]
    }
    fn mulmod(a: &U, b: &U, m: &U) -> U {
        mod_gen(&mul512(a, b), m)
    }
    fn addmod(a: &U, b: &U, m: &U) -> U {
        let mut s = [0u64; 5];
        let mut c = 0u128;
        for i in 0..4 {
            let t = a[i] as u128 + b[i] as u128 + c;
            s[i] = t as u64;
            c = t >> 64;
        }
        s[4] = c as u64;
        let m5 = [m[0], m[1], m[2], m[3], 0];
        if ge5(&s, &m5) {
            sub5(&mut s, &m5);
        }
        [s[0], s[1], s[2], s[3]]
    }
    fn submod(a: &U, b: &U, m: &U) -> U {
        if ge4(a, b) {
            let mut r = *a;
            let mut br = 0i128;
            for i in 0..4 {
                let v = r[i] as i128 - b[i] as i128 - br;
                if v < 0 {
                    r[i] = (v + (1i128 << 64)) as u64;
                    br = 1;
                } else {
                    r[i] = v as u64;
                    br = 0;
                }
            }
            r
        } else {
            addmod(a, &submod(m, b, m), m)
        }
    }
    fn sub_small(a: &U, k: u64) -> U {
        let mut r = *a;
        let mut br = k as i128;
        for i in 0..4 {
            let v = r[i] as i128 - br;
            if v < 0 {
                r[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                r[i] = v as u64;
                br = 0;
            }
        }
        r
    }
    fn powmod(a: &U, e: &U, m: &U) -> U {
        let mut r = [1u64, 0, 0, 0];
        let mut base = *a;
        for i in 0..256 {
            if (e[i / 64] >> (i % 64)) & 1 == 1 {
                r = mulmod(&r, &base, m);
            }
            base = mulmod(&base, &base, m);
        }
        r
    }
    fn invmod(a: &U, m: &U) -> U {
        powmod(a, &sub_small(m, 2), m)
    } // a^(m-2)

    // Jacobian point (X:Y:Z); affine (X/Z², Y/Z³). a = -3.
    #[derive(Clone, Copy)]
    struct Jac {
        x: U,
        y: U,
        z: U,
    }
    fn jinf() -> Jac {
        Jac {
            x: [1, 0, 0, 0],
            y: [1, 0, 0, 0],
            z: [0, 0, 0, 0],
        }
    }
    fn fmul(a: &U, b: &U) -> U {
        mulmod(a, b, &P)
    }
    fn fsq(a: &U) -> U {
        mulmod(a, a, &P)
    }
    fn fadd(a: &U, b: &U) -> U {
        addmod(a, b, &P)
    }
    fn fsub(a: &U, b: &U) -> U {
        submod(a, b, &P)
    }

    fn jdouble(p: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *p;
        }
        let delta = fsq(&p.z);
        let gamma = fsq(&p.y);
        let beta = fmul(&p.x, &gamma);
        let t = fmul(&fsub(&p.x, &delta), &fadd(&p.x, &delta));
        let alpha = fadd(&fadd(&t, &t), &t); // 3(X-δ)(X+δ)
        let x3 = fsub(&fsq(&alpha), &{
            let b2 = fadd(&beta, &beta);
            let b4 = fadd(&b2, &b2);
            fadd(&b4, &b4)
        }); // 8·beta
        let z3 = fsub(&fsub(&fsq(&fadd(&p.y, &p.z)), &gamma), &delta);
        let g2 = fsq(&gamma);
        let g8 = {
            let a = fadd(&g2, &g2);
            let b = fadd(&a, &a);
            fadd(&b, &b)
        };
        let b4 = {
            let a = fadd(&beta, &beta);
            fadd(&a, &a)
        };
        let y3 = fsub(&fmul(&alpha, &fsub(&b4, &x3)), &g8);
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jadd(p: &Jac, q: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *q;
        }
        if is_zero(&q.z) {
            return *p;
        }
        let z1z1 = fsq(&p.z);
        let z2z2 = fsq(&q.z);
        let u1 = fmul(&p.x, &z2z2);
        let u2 = fmul(&q.x, &z1z1);
        let s1 = fmul(&fmul(&p.y, &q.z), &z2z2);
        let s2 = fmul(&fmul(&q.y, &p.z), &z1z1);
        if u1 == u2 {
            if s1 == s2 {
                return jdouble(p);
            } else {
                return jinf();
            }
        }
        let h = fsub(&u2, &u1);
        let i = fsq(&fadd(&h, &h));
        let j = fmul(&h, &i);
        let rr = fadd(&fsub(&s2, &s1), &fsub(&s2, &s1));
        let v = fmul(&u1, &i);
        let x3 = fsub(&fsub(&fsq(&rr), &j), &fadd(&v, &v));
        let y3 = fsub(&fmul(&rr, &fsub(&v, &x3)), &fmul(&fadd(&s1, &s1), &j));
        let z3 = fmul(&fsub(&fsub(&fsq(&fadd(&p.z, &q.z)), &z1z1), &z2z2), &h);
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jscalar(k: &U, p: &Jac) -> Jac {
        let mut r = jinf();
        for i in (0..256).rev() {
            r = jdouble(&r);
            if (k[i / 64] >> (i % 64)) & 1 == 1 {
                r = jadd(&r, p);
            }
        }
        r
    }
    /// The affine x-coordinate of a Jacobian point (None at infinity).
    fn affine_x(p: &Jac) -> Option<U> {
        if is_zero(&p.z) {
            return None;
        }
        let zi = invmod(&p.z, &P);
        Some(fmul(&p.x, &fsq(&zi)))
    }

    /// Verify an ECDSA/P-256 signature: `pubkey` = `Qx‖Qy` (64B), `hash` = the message digest (32B, e.g.
    /// our SHA-256), `sig` = `r‖s` (64B). Returns true iff valid — the one-cell friction check.
    pub fn ecdsa_p256_verify(pubkey: &[u8; 64], hash: &[u8; 32], sig: &[u8; 64]) -> bool {
        let qx = from_be(&pubkey[..32]);
        let qy = from_be(&pubkey[32..]);
        let r = from_be(&sig[..32]);
        let s = from_be(&sig[32..]);
        if is_zero(&r) || ge4(&r, &N) || is_zero(&s) || ge4(&s, &N) {
            return false;
        }
        let e = from_be(hash);
        let w = invmod(&s, &N);
        let u1 = mulmod(&e, &w, &N);
        let u2 = mulmod(&r, &w, &N);
        let g = Jac {
            x: GX,
            y: GY,
            z: [1, 0, 0, 0],
        };
        let q = Jac {
            x: qx,
            y: qy,
            z: [1, 0, 0, 0],
        };
        let pt = jadd(&jscalar(&u1, &g), &jscalar(&u2, &q));
        match affine_x(&pt) {
            None => false,
            Some(x1) => {
                let mut xr = [0u64; 8];
                xr[..4].copy_from_slice(&x1);
                mod_gen(&xr, &N) == r
            } // x1 mod n == r
        }
    }

    fn to_be32(u: &U) -> [u8; 32] {
        let mut b = [0u8; 32];
        for i in 0..4 {
            b[24 - i * 8..32 - i * 8].copy_from_slice(&u[i].to_be_bytes());
        }
        b
    }
    fn hmac(k: &[u8], d: &[u8]) -> [u8; 32] {
        crate::hashtrinity::crypto::hmac_sha256(k, d)
    }

    /// RFC 6979 §3.2 deterministic nonce for P-256/SHA-256 (HMAC-DRBG). No RNG — reproducible + safe.
    fn rfc6979_k(xo: &[u8; 32], ho: &[u8; 32]) -> U {
        let mut v = [1u8; 32];
        let mut k = [0u8; 32];
        let seed = |flag: u8, k: &[u8; 32], v: &[u8; 32]| {
            let mut b = v.to_vec();
            b.push(flag);
            b.extend_from_slice(xo);
            b.extend_from_slice(ho);
            hmac(k, &b)
        };
        k = seed(0x00, &k, &v);
        v = hmac(&k, &v);
        k = seed(0x01, &k, &v);
        v = hmac(&k, &v);
        loop {
            v = hmac(&k, &v);
            let cand = from_be(&v);
            if !is_zero(&cand) && !ge4(&cand, &N) {
                return cand;
            }
            let mut b = v.to_vec();
            b.push(0x00);
            k = hmac(&k, &b);
            v = hmac(&k, &v);
        }
    }

    /// ECDSA/P-256 sign (RFC 6979 deterministic). Returns `r‖s` (64B, the raw JWT/SVID form).
    pub fn ecdsa_p256_sign(private_key: &[u8; 32], hash: &[u8; 32]) -> [u8; 64] {
        let d = from_be(private_key);
        let mut he = [0u64; 8];
        he[..4].copy_from_slice(&from_be(hash));
        let e = mod_gen(&he, &N); // e mod n
        let k = rfc6979_k(private_key, &to_be32(&e));
        let g = Jac {
            x: GX,
            y: GY,
            z: [1, 0, 0, 0],
        };
        let mut rx8 = [0u64; 8];
        rx8[..4].copy_from_slice(&affine_x(&jscalar(&k, &g)).unwrap());
        let r = mod_gen(&rx8, &N); // r = (k·G).x mod n
        let kinv = invmod(&k, &N);
        let s = mulmod(&kinv, &addmod(&e, &mulmod(&r, &d, &N), &N), &N); // s = k⁻¹(e + r·d) mod n
        let mut sig = [0u8; 64];
        sig[..32].copy_from_slice(&to_be32(&r));
        sig[32..].copy_from_slice(&to_be32(&s));
        sig
    }

    fn affine(p: &Jac) -> Option<(U, U)> {
        if is_zero(&p.z) {
            return None;
        }
        let zi = invmod(&p.z, &P);
        let zi2 = fsq(&zi);
        Some((fmul(&p.x, &zi2), fmul(&fmul(&p.y, &zi2), &zi)))
    }
    /// P-256 public key (`x‖y`, 64B) from a 32-byte secret.
    pub fn p256_pubkey(secret: &[u8; 32]) -> [u8; 64] {
        let (x, y) = affine(&jscalar(
            &from_be(secret),
            &Jac {
                x: GX,
                y: GY,
                z: [1, 0, 0, 0],
            },
        ))
        .unwrap();
        let mut o = [0u8; 64];
        o[..32].copy_from_slice(&to_be32(&x));
        o[32..].copy_from_slice(&to_be32(&y));
        o
    }
    /// ECDH on P-256: shared secret = x-coordinate of `secret · peer_pubkey` (the TLS ECDHE agreement).
    pub fn ecdh_p256(secret: &[u8; 32], peer_pubkey: &[u8; 64]) -> Option<[u8; 32]> {
        let q = Jac {
            x: from_be(&peer_pubkey[..32]),
            y: from_be(&peer_pubkey[32..]),
            z: [1, 0, 0, 0],
        };
        Some(to_be32(&affine_x(&jscalar(&from_be(secret), &q))?))
    }
}
pub mod jwt {
    //! JWT / JWS (RFC 7519 / 7515) + EdDSA (RFC 8037) — a **format is PARSE + our signature fold.** The
    //! token is `base64url(header).base64url(payload).base64url(sig)`; parsing is the universal decode,
    //! the signature is HMAC-SHA256 (HS256, our nested fold) or Ed25519 (EdDSA, our group-merge). This is
    //! the same shape as x509 (DER-parse + verify + a chain-**fold**) and OIDC (a JWT + a JWKS lookup):
    //! nothing new below — the crate's existing primitives, plus a parse.
    use crate::hashtrinity::crypto::{ct_eq, ed25519_sign, ed25519_verify, hmac_sha256};

    const B64: &[u8; 64] = b"ABCDEFGHIJKLMNOPQRSTUVWXYZabcdefghijklmnopqrstuvwxyz0123456789-_";

    fn b64url_encode(b: &[u8]) -> String {
        let mut s = String::with_capacity(b.len() * 4 / 3 + 1);
        let (mut acc, mut nbits) = (0u32, 0u32);
        for &byte in b {
            acc = (acc << 8) | byte as u32;
            nbits += 8;
            while nbits >= 6 {
                nbits -= 6;
                s.push(B64[((acc >> nbits) & 63) as usize] as char);
            }
        }
        if nbits > 0 {
            s.push(B64[((acc << (6 - nbits)) & 63) as usize] as char);
        }
        s
    }
    fn b64url_decode(s: &str) -> Option<Vec<u8>> {
        let val = |c: u8| -> Option<u32> {
            match c {
                b'A'..=b'Z' => Some((c - b'A') as u32),
                b'a'..=b'z' => Some((c - b'a' + 26) as u32),
                b'0'..=b'9' => Some((c - b'0' + 52) as u32),
                b'-' => Some(62),
                b'_' => Some(63),
                _ => None,
            }
        };
        let (mut acc, mut nbits) = (0u32, 0u32);
        let mut out = Vec::with_capacity(s.len() * 3 / 4);
        for c in s.bytes() {
            acc = (acc << 6) | val(c)?;
            nbits += 6;
            if nbits >= 8 {
                nbits -= 8;
                out.push((acc >> nbits) as u8);
            }
        }
        Some(out)
    }

    /// The verification key. HS256/EdDSA plus the SPIFFE JWT-SVID / WIMSE-WIT algorithms: **ES256** (raw
    /// P-256 pubkey `x‖y`) and **RS256** (RSA modulus `n` + exponent `e`). JWT signatures are raw (ES256 =
    /// `r‖s`, not DER), which is exactly what our verifiers take.
    pub enum JwtKey<'a> {
        Hs256(&'a [u8]),
        EdDSA(&'a [u8; 32]),
        Es256(&'a [u8; 64]),
        Rs256 { n: &'a [u8], e: u64 },
    }

    /// Verify a JWS compact token. Returns the decoded payload bytes iff the signature is valid. The
    /// signing input is the token's own `header.payload` bytes (never re-encoded).
    pub fn jwt_verify(token: &str, key: &JwtKey) -> Option<Vec<u8>> {
        use crate::hashtrinity::crypto::{ecdsa_p256_verify, rsa_pkcs1_sha256_verify, sha256};
        let parts: Vec<&str> = token.split('.').collect();
        if parts.len() != 3 {
            return None;
        }
        let signing_input = format!("{}.{}", parts[0], parts[1]);
        let sig = b64url_decode(parts[2])?;
        let ok = match key {
            JwtKey::Hs256(k) => ct_eq(&hmac_sha256(k, signing_input.as_bytes()), &sig),
            JwtKey::EdDSA(pk) => {
                if sig.len() != 64 {
                    return None;
                }
                let mut s = [0u8; 64];
                s.copy_from_slice(&sig);
                ed25519_verify(pk, signing_input.as_bytes(), &s)
            }
            JwtKey::Es256(pk) => {
                if sig.len() != 64 {
                    return None;
                } // JWT ES256 sig is the raw r‖s
                let mut s = [0u8; 64];
                s.copy_from_slice(&sig);
                ecdsa_p256_verify(pk, &sha256(signing_input.as_bytes()), &s)
            }
            JwtKey::Rs256 { n, e } => {
                rsa_pkcs1_sha256_verify(n, *e, &sig, &sha256(signing_input.as_bytes()))
            }
        };
        if ok {
            b64url_decode(parts[1])
        } else {
            None
        }
    }

    /// Mint an EdDSA (RFC 8037) JWS from a raw header + payload JSON.
    pub fn jwt_sign_eddsa(sk: &[u8; 32], header_json: &str, payload_json: &str) -> String {
        let si = format!(
            "{}.{}",
            b64url_encode(header_json.as_bytes()),
            b64url_encode(payload_json.as_bytes())
        );
        let sig = ed25519_sign(sk, si.as_bytes());
        format!("{}.{}", si, b64url_encode(&sig))
    }

    /// Mint an HS256 JWS from a raw header + payload JSON — the mirror of `jwt_verify`'s
    /// `JwtKey::Hs256` path.
    pub fn jwt_sign_hs256(key: &[u8], header_json: &str, payload_json: &str) -> String {
        let si = format!(
            "{}.{}",
            b64url_encode(header_json.as_bytes()),
            b64url_encode(payload_json.as_bytes())
        );
        let sig = hmac_sha256(key, si.as_bytes());
        format!("{}.{}", si, b64url_encode(&sig))
    }

    /// Mint an ES256 JWS (SPIFFE JWT-SVID / WIMSE WIT) — ECDSA P-256 over the signing input, raw r‖s.
    pub fn jwt_sign_es256(private_key: &[u8; 32], header_json: &str, payload_json: &str) -> String {
        let si = format!(
            "{}.{}",
            b64url_encode(header_json.as_bytes()),
            b64url_encode(payload_json.as_bytes())
        );
        let sig = crate::hashtrinity::crypto::ecdsa_p256_sign(private_key, &crate::hashtrinity::crypto::sha256(si.as_bytes()));
        format!("{}.{}", si, b64url_encode(&sig))
    }
}
pub use ecdsa::{ecdh_p256, ecdsa_p256_sign, ecdsa_p256_verify, p256_pubkey};
pub mod acme {
    //! ACME (RFC 8555) crypto — the sovereign pieces of automated certificate issuance. ACME requests are
    //! JWS signed by the account key (our ed25519/ES256/RS256 signers); the challenge **key authorization**
    //! is `token ‖ "." ‖ base64url(JWK thumbprint)`; the **JWK thumbprint** is RFC 7638 (SHA-256 of the
    //! canonical JWK). This module is the thumbprint + key-authorization + CSR; the HTTP flow is a client.
    use crate::hashtrinity::crypto::sha256;

    /// base64url, no padding (JWK member encoding + the thumbprint/key-auth encoding).
    pub fn b64url(d: &[u8]) -> String {
        const A: &[u8; 64] = b"ABCDEFGHIJKLMNOPQRSTUVWXYZabcdefghijklmnopqrstuvwxyz0123456789-_";
        let mut s = String::with_capacity(d.len() * 4 / 3 + 1);
        let (mut acc, mut nb) = (0u32, 0u32);
        for &x in d {
            acc = (acc << 8) | x as u32;
            nb += 8;
            while nb >= 6 {
                nb -= 6;
                s.push(A[((acc >> nb) & 63) as usize] as char);
            }
        }
        if nb > 0 {
            s.push(A[((acc << (6 - nb)) & 63) as usize] as char);
        }
        s
    }

    /// RFC 7638 JWK thumbprint for an RSA key: `SHA-256({"e":..,"kty":"RSA","n":..})` (members lexically
    /// ordered, no whitespace — the required members only).
    pub fn jwk_thumbprint_rsa(n_be: &[u8], e_be: &[u8]) -> [u8; 32] {
        sha256(
            format!(
                r#"{{"e":"{}","kty":"RSA","n":"{}"}}"#,
                b64url(e_be),
                b64url(n_be)
            )
            .as_bytes(),
        )
    }
    /// RFC 7638 thumbprint for an EC P-256 key: `SHA-256({"crv":"P-256","kty":"EC","x":..,"y":..})`.
    pub fn jwk_thumbprint_ec_p256(x: &[u8; 32], y: &[u8; 32]) -> [u8; 32] {
        sha256(
            format!(
                r#"{{"crv":"P-256","kty":"EC","x":"{}","y":"{}"}}"#,
                b64url(x),
                b64url(y)
            )
            .as_bytes(),
        )
    }
    /// RFC 7638 thumbprint for an ed25519 (OKP) key: `SHA-256({"crv":"Ed25519","kty":"OKP","x":..})`.
    pub fn jwk_thumbprint_ed25519(pk: &[u8; 32]) -> [u8; 32] {
        sha256(format!(r#"{{"crv":"Ed25519","kty":"OKP","x":"{}"}}"#, b64url(pk)).as_bytes())
    }

    /// The ACME challenge **key authorization** (RFC 8555 §8.1): `token ‖ "." ‖ base64url(thumbprint)`.
    /// HTTP-01 serves this at `/.well-known/acme-challenge/<token>`; DNS-01 publishes `SHA-256` of it.
    pub fn acme_key_authorization(token: &str, account_thumbprint: &[u8; 32]) -> String {
        format!("{}.{}", token, b64url(account_thumbprint))
    }
    /// The DNS-01 TXT record value: `base64url(SHA-256(key_authorization))`.
    pub fn acme_dns01_txt(token: &str, account_thumbprint: &[u8; 32]) -> String {
        b64url(&sha256(
            acme_key_authorization(token, account_thumbprint).as_bytes(),
        ))
    }
}
pub mod aes_cbc {
    //! AES-CBC + PKCS#7 (still in TLS 1.2, disk encryption, PBES2, lots of legacy). Reuses the block
    //! cipher from `aes_gcm` (forward for encrypt, the inverse cipher for decrypt). Gated vs openssl.
    use crate::hashtrinity::crypto::aes_gcm::{decrypt_block, encrypt_block, expand128_w, expand256_w};

    fn cbc_encrypt(w: &[u32], iv: &[u8; 16], pt: &[u8]) -> Vec<u8> {
        let pad = 16 - (pt.len() % 16);
        let mut data = pt.to_vec();
        data.extend(core::iter::repeat(pad as u8).take(pad)); // PKCS#7
        let mut prev = *iv;
        let mut out = Vec::with_capacity(data.len());
        for chunk in data.chunks(16) {
            let mut blk = [0u8; 16];
            blk.copy_from_slice(chunk);
            for i in 0..16 {
                blk[i] ^= prev[i];
            }
            let ct = encrypt_block(w, &blk);
            out.extend_from_slice(&ct);
            prev = ct;
        }
        out
    }
    fn cbc_decrypt(w: &[u32], iv: &[u8; 16], ct: &[u8]) -> Option<Vec<u8>> {
        if ct.is_empty() || ct.len() % 16 != 0 {
            return None;
        }
        let mut prev = *iv;
        let mut out = Vec::with_capacity(ct.len());
        for chunk in ct.chunks(16) {
            let mut blk = [0u8; 16];
            blk.copy_from_slice(chunk);
            let mut pt = decrypt_block(w, &blk);
            for i in 0..16 {
                pt[i] ^= prev[i];
            }
            out.extend_from_slice(&pt);
            prev = blk;
        }
        let pad = *out.last()? as usize; // strip PKCS#7
        if pad == 0 || pad > 16 || pad > out.len() {
            return None;
        }
        if out[out.len() - pad..].iter().any(|&b| b as usize != pad) {
            return None;
        }
        out.truncate(out.len() - pad);
        Some(out)
    }

    /// AES-128-CBC encrypt with PKCS#7 padding.
    pub fn aes128_cbc_encrypt(key: &[u8; 16], iv: &[u8; 16], pt: &[u8]) -> Vec<u8> {
        cbc_encrypt(&expand128_w(key), iv, pt)
    }
    /// AES-128-CBC decrypt + PKCS#7 unpad (None on bad padding).
    pub fn aes128_cbc_decrypt(key: &[u8; 16], iv: &[u8; 16], ct: &[u8]) -> Option<Vec<u8>> {
        cbc_decrypt(&expand128_w(key), iv, ct)
    }
    /// AES-256-CBC encrypt with PKCS#7 padding.
    pub fn aes256_cbc_encrypt(key: &[u8; 32], iv: &[u8; 16], pt: &[u8]) -> Vec<u8> {
        cbc_encrypt(&expand256_w(key), iv, pt)
    }
    /// AES-256-CBC decrypt + PKCS#7 unpad.
    pub fn aes256_cbc_decrypt(key: &[u8; 32], iv: &[u8; 16], ct: &[u8]) -> Option<Vec<u8>> {
        cbc_decrypt(&expand256_w(key), iv, ct)
    }
}
pub mod aes_ctr {
    //! AES-256-CTR (raw, no AEAD) — the bare counter-mode stream cipher: a 128-bit big-endian counter
    //! block that STARTS AT THE IV and increments as one 128-bit integer across all 16 bytes (the
    //! `ctr::Ctr128BE<Aes256>` convention Ansible Vault and the Python `cryptography` library's
    //! `modes.CTR(iv)` both use). This is NOT GCM's internal counter (`aes_gcm::inc32`, which fixes a
    //! 96-bit IV and rolls only the last 4 bytes) — different construction, same AES-256 block core.
    //! Symmetric: the same call encrypts or decrypts (XOR with the keystream).

    use crate::hashtrinity::crypto::aes_gcm::{encrypt_block, expand256};

    fn inc128(ctr: &mut [u8; 16]) {
        for byte in ctr.iter_mut().rev() {
            *byte = byte.wrapping_add(1);
            if *byte != 0 {
                break;
            }
        }
    }

    /// XOR `data` with the AES-256-CTR keystream, counter starting at `iv`. Same operation encrypts
    /// or decrypts.
    pub fn aes256_ctr(key: &[u8; 32], iv: &[u8; 16], data: &[u8]) -> Vec<u8> {
        let w = expand256(key);
        let mut ctr = *iv;
        let mut out = Vec::with_capacity(data.len());
        for chunk in data.chunks(16) {
            let ks = encrypt_block(&w, &ctr);
            out.extend(chunk.iter().zip(ks.iter()).map(|(b, k)| b ^ k));
            inc128(&mut ctr);
        }
        out
    }
}
pub mod aes_gcm {
    //! AES-128/256-GCM (FIPS 197 + SP 800-38D) — the TLS record cipher, and (128-bit) the HPKE
    //! ciphersuite ODoH (RFC 9230) needs. AES block (the S-box = GF(2⁸) inverse + affine, computed
    //! not transcribed), CTR keystream (the XOR-fold), GHASH (GF(2¹²⁸)) — one block core, one GCM
    //! core, parameterized only by the key-schedule length (`encrypt_block`/`gcm_core`/`gcm_tag` take
    //! `&[u32]` and read the round count off it, so 128 and 256 share every line past key expansion).
    //! Encrypt-then-authenticate; decrypt verifies the tag BEFORE returning (integrity at the cell).
    //! Gated on NIST GCM test vectors. Zero-dep outside `hashtrinity`.
    #![allow(clippy::needless_range_loop)]
    use std::sync::OnceLock;

    // ── GF(2⁸) for AES ────────────────────────────────────────────────────────────────────────────────
    fn gmul(mut a: u8, mut b: u8) -> u8 {
        let mut p = 0u8;
        for _ in 0..8 {
            if b & 1 != 0 {
                p ^= a;
            }
            let hi = a & 0x80;
            a <<= 1;
            if hi != 0 {
                a ^= 0x1b;
            }
            b >>= 1;
        }
        p
    }
    fn sbox() -> &'static [u8; 256] {
        static S: OnceLock<[u8; 256]> = OnceLock::new();
        S.get_or_init(|| {
            let mut inv = [0u8; 256];
            for a in 1..256u16 {
                for b in 1..256u16 {
                    if gmul(a as u8, b as u8) == 1 {
                        inv[a as usize] = b as u8;
                        break;
                    }
                }
            }
            let mut s = [0u8; 256];
            for i in 0..256 {
                let x = inv[i];
                s[i] = x
                    ^ x.rotate_left(1)
                    ^ x.rotate_left(2)
                    ^ x.rotate_left(3)
                    ^ x.rotate_left(4)
                    ^ 0x63;
            }
            s
        })
    }

    // ── AES-256 key schedule + block encrypt ──────────────────────────────────────────────────────────
    // `pub(crate)`: the raw block cipher is the shared primitive `aes_ctr` (plain CTR, no AEAD) reuses
    // rather than re-deriving its own S-box/key-schedule copy — one AES-256 core, two modes on top.
    pub(crate) fn expand256(key: &[u8; 32]) -> [u32; 60] {
        let s = sbox();
        let subword = |w: u32| {
            let b = w.to_be_bytes();
            u32::from_be_bytes([
                s[b[0] as usize],
                s[b[1] as usize],
                s[b[2] as usize],
                s[b[3] as usize],
            ])
        };
        let rcon = [
            0x01000000u32,
            0x02000000,
            0x04000000,
            0x08000000,
            0x10000000,
            0x20000000,
            0x40000000,
        ];
        let mut w = [0u32; 60];
        for i in 0..8 {
            w[i] = u32::from_be_bytes([key[4 * i], key[4 * i + 1], key[4 * i + 2], key[4 * i + 3]]);
        }
        for i in 8..60 {
            let mut t = w[i - 1];
            if i % 8 == 0 {
                t = subword(t.rotate_left(8)) ^ rcon[i / 8 - 1];
            } else if i % 8 == 4 {
                t = subword(t);
            }
            w[i] = w[i - 8] ^ t;
        }
        w
    }
    /// AES-128 key schedule (Nk=4, Nr=10, 44 round-key words) — the ODoH/HPKE ciphersuite. Same
    /// S-box/rotword/subword machinery as `expand256`, only the trigger period (every 4 words, not
    /// every 8) and the rcon table (10 rounds' worth) differ.
    pub(crate) fn expand128(key: &[u8; 16]) -> [u32; 44] {
        let s = sbox();
        let subword = |w: u32| {
            let b = w.to_be_bytes();
            u32::from_be_bytes([
                s[b[0] as usize],
                s[b[1] as usize],
                s[b[2] as usize],
                s[b[3] as usize],
            ])
        };
        let rcon = [
            0x01000000u32,
            0x02000000,
            0x04000000,
            0x08000000,
            0x10000000,
            0x20000000,
            0x40000000,
            0x80000000,
            0x1b000000,
            0x36000000,
        ];
        let mut w = [0u32; 44];
        for i in 0..4 {
            w[i] = u32::from_be_bytes([key[4 * i], key[4 * i + 1], key[4 * i + 2], key[4 * i + 3]]);
        }
        for i in 4..44 {
            let mut t = w[i - 1];
            if i % 4 == 0 {
                t = subword(t.rotate_left(8)) ^ rcon[i / 4 - 1];
            }
            w[i] = w[i - 4] ^ t;
        }
        w
    }
    fn add_rk(st: &mut [u8; 16], w: &[u32]) {
        for c in 0..4 {
            let b = w[c].to_be_bytes();
            for r in 0..4 {
                st[4 * c + r] ^= b[r];
            }
        }
    }
    fn sub_bytes(st: &mut [u8; 16]) {
        let s = sbox();
        for x in st.iter_mut() {
            *x = s[*x as usize];
        }
    }
    fn shift_rows(st: &mut [u8; 16]) {
        let o = *st;
        for c in 0..4 {
            for r in 0..4 {
                st[4 * c + r] = o[4 * ((c + r) % 4) + r];
            }
        }
    }
    fn mix_cols(st: &mut [u8; 16]) {
        for c in 0..4 {
            let (a0, a1, a2, a3) = (st[4 * c], st[4 * c + 1], st[4 * c + 2], st[4 * c + 3]);
            st[4 * c] = gmul(a0, 2) ^ gmul(a1, 3) ^ a2 ^ a3;
            st[4 * c + 1] = a0 ^ gmul(a1, 2) ^ gmul(a2, 3) ^ a3;
            st[4 * c + 2] = a0 ^ a1 ^ gmul(a2, 2) ^ gmul(a3, 3);
            st[4 * c + 3] = gmul(a0, 3) ^ a1 ^ a2 ^ gmul(a3, 2);
        }
    }
    /// AES block encrypt — Nr (10 for AES-128, 14 for AES-256) read off the schedule length
    /// (`w.len() = 4*(Nr+1)`), so this one loop serves both `expand128` and `expand256`.
    pub(crate) fn encrypt_block(w: &[u32], inp: &[u8; 16]) -> [u8; 16] {
        let nr = w.len() / 4 - 1;
        let mut st = *inp;
        add_rk(&mut st, &w[0..4]);
        for round in 1..nr {
            sub_bytes(&mut st);
            shift_rows(&mut st);
            mix_cols(&mut st);
            add_rk(&mut st, &w[round * 4..round * 4 + 4]);
        }
        sub_bytes(&mut st);
        shift_rows(&mut st);
        add_rk(&mut st, &w[nr * 4..nr * 4 + 4]);
        st
    }

    fn inv_sbox() -> &'static [u8; 256] {
        static IS: OnceLock<[u8; 256]> = OnceLock::new();
        IS.get_or_init(|| {
            let s = sbox();
            let mut is = [0u8; 256];
            for i in 0..256 {
                is[s[i] as usize] = i as u8;
            }
            is
        })
    }
    fn inv_sub_bytes(st: &mut [u8; 16]) {
        let s = inv_sbox();
        for x in st.iter_mut() {
            *x = s[*x as usize];
        }
    }
    fn inv_shift_rows(st: &mut [u8; 16]) {
        let o = *st;
        for c in 0..4 {
            for r in 0..4 {
                st[4 * c + r] = o[4 * ((c + 4 - r) % 4) + r];
            }
        }
    }
    fn inv_mix_cols(st: &mut [u8; 16]) {
        for c in 0..4 {
            let (a0, a1, a2, a3) = (st[4 * c], st[4 * c + 1], st[4 * c + 2], st[4 * c + 3]);
            st[4 * c] = gmul(a0, 0x0e) ^ gmul(a1, 0x0b) ^ gmul(a2, 0x0d) ^ gmul(a3, 0x09);
            st[4 * c + 1] = gmul(a0, 0x09) ^ gmul(a1, 0x0e) ^ gmul(a2, 0x0b) ^ gmul(a3, 0x0d);
            st[4 * c + 2] = gmul(a0, 0x0d) ^ gmul(a1, 0x09) ^ gmul(a2, 0x0e) ^ gmul(a3, 0x0b);
            st[4 * c + 3] = gmul(a0, 0x0b) ^ gmul(a1, 0x0d) ^ gmul(a2, 0x09) ^ gmul(a3, 0x0e);
        }
    }
    /// AES block decrypt — the inverse cipher (used by CBC). Nr read off the schedule length.
    pub(crate) fn decrypt_block(w: &[u32], inp: &[u8; 16]) -> [u8; 16] {
        let nr = w.len() / 4 - 1;
        let mut st = *inp;
        add_rk(&mut st, &w[nr * 4..nr * 4 + 4]);
        inv_shift_rows(&mut st);
        inv_sub_bytes(&mut st);
        for round in (1..nr).rev() {
            add_rk(&mut st, &w[round * 4..round * 4 + 4]);
            inv_mix_cols(&mut st);
            inv_shift_rows(&mut st);
            inv_sub_bytes(&mut st);
        }
        add_rk(&mut st, &w[0..4]);
        st
    }
    pub(crate) fn expand128_w(key: &[u8; 16]) -> [u32; 44] {
        expand128(key)
    }
    pub(crate) fn expand256_w(key: &[u8; 32]) -> [u32; 60] {
        expand256(key)
    }

    // ── GHASH (GF(2¹²⁸)) + GCM ────────────────────────────────────────────────────────────────────────
    fn gcm_mul(x: &[u8; 16], y: &[u8; 16]) -> [u8; 16] {
        let mut z = [0u8; 16];
        let mut v = *y;
        for i in 0..128 {
            if (x[i / 8] >> (7 - (i % 8))) & 1 == 1 {
                for j in 0..16 {
                    z[j] ^= v[j];
                }
            }
            let lsb = v[15] & 1;
            for j in (1..16).rev() {
                v[j] = (v[j] >> 1) | (v[j - 1] << 7);
            }
            v[0] >>= 1;
            if lsb == 1 {
                v[0] ^= 0xe1;
            }
        }
        z
    }
    fn ghash(h: &[u8; 16], data: &[u8]) -> [u8; 16] {
        let mut y = [0u8; 16];
        for chunk in data.chunks(16) {
            let mut blk = [0u8; 16];
            blk[..chunk.len()].copy_from_slice(chunk);
            for j in 0..16 {
                y[j] ^= blk[j];
            }
            y = gcm_mul(&y, h);
        }
        y
    }
    fn inc32(ctr: &mut [u8; 16]) {
        for i in (12..16).rev() {
            ctr[i] = ctr[i].wrapping_add(1);
            if ctr[i] != 0 {
                break;
            }
        }
    }

    fn gcm_core(w: &[u32], iv: &[u8; 12], input: &[u8]) -> (Vec<u8>, [u8; 16]) {
        let h = encrypt_block(w, &[0u8; 16]);
        let mut j0 = [0u8; 16];
        j0[..12].copy_from_slice(iv);
        j0[15] = 1;
        let mut out = Vec::with_capacity(input.len());
        let mut ctr = j0;
        for chunk in input.chunks(16) {
            inc32(&mut ctr);
            let ks = encrypt_block(w, &ctr);
            for (i, &b) in chunk.iter().enumerate() {
                out.push(b ^ ks[i]);
            }
        }
        (out, h) // caller GHASHes over the ciphertext (enc) or the input ciphertext (dec)
                 // note: for GCM, GHASH is always over the CIPHERTEXT
    }
    /// AES-256-GCM encrypt: `(ciphertext, 16-byte tag)`.
    pub fn aes256_gcm_encrypt(
        key: &[u8; 32],
        iv: &[u8; 12],
        pt: &[u8],
        aad: &[u8],
    ) -> (Vec<u8>, [u8; 16]) {
        let w = expand256(key);
        let (ct, h) = gcm_core(&w, iv, pt);
        let tag = gcm_tag(&w, iv, &h, &ct, aad);
        (ct, tag)
    }
    /// AES-256-GCM decrypt: verifies the tag first, returns `None` on tamper (integrity at the cell).
    pub fn aes256_gcm_decrypt(
        key: &[u8; 32],
        iv: &[u8; 12],
        ct: &[u8],
        tag: &[u8; 16],
        aad: &[u8],
    ) -> Option<Vec<u8>> {
        let w = expand256(key);
        let h = encrypt_block(&w, &[0u8; 16]);
        let expect = gcm_tag(&w, iv, &h, ct, aad);
        let mut d = 0u8;
        for i in 0..16 {
            d |= expect[i] ^ tag[i];
        }
        if d != 0 {
            return None;
        } // tamper → refuse
        let (pt, _) = gcm_core(&w, iv, ct);
        Some(pt)
    }
    /// AES-128-GCM encrypt: `(ciphertext, 16-byte tag)` — the ODoH/HPKE ciphersuite.
    pub fn aes128_gcm_encrypt(
        key: &[u8; 16],
        iv: &[u8; 12],
        pt: &[u8],
        aad: &[u8],
    ) -> (Vec<u8>, [u8; 16]) {
        let w = expand128(key);
        let (ct, h) = gcm_core(&w, iv, pt);
        let tag = gcm_tag(&w, iv, &h, &ct, aad);
        (ct, tag)
    }
    /// AES-128-GCM decrypt: verifies the tag first, returns `None` on tamper (integrity at the cell).
    pub fn aes128_gcm_decrypt(
        key: &[u8; 16],
        iv: &[u8; 12],
        ct: &[u8],
        tag: &[u8; 16],
        aad: &[u8],
    ) -> Option<Vec<u8>> {
        let w = expand128(key);
        let h = encrypt_block(&w, &[0u8; 16]);
        let expect = gcm_tag(&w, iv, &h, ct, aad);
        let mut d = 0u8;
        for i in 0..16 {
            d |= expect[i] ^ tag[i];
        }
        if d != 0 {
            return None;
        }
        let (pt, _) = gcm_core(&w, iv, ct);
        Some(pt)
    }
    fn gcm_tag(w: &[u32], iv: &[u8; 12], h: &[u8; 16], ct: &[u8], aad: &[u8]) -> [u8; 16] {
        let mut g = Vec::new();
        g.extend_from_slice(aad);
        while g.len() % 16 != 0 {
            g.push(0);
        }
        g.extend_from_slice(ct);
        while g.len() % 16 != 0 {
            g.push(0);
        }
        g.extend_from_slice(&((aad.len() as u64) * 8).to_be_bytes());
        g.extend_from_slice(&((ct.len() as u64) * 8).to_be_bytes());
        let s = ghash(h, &g);
        let mut j0 = [0u8; 16];
        j0[..12].copy_from_slice(iv);
        j0[15] = 1;
        let ej0 = encrypt_block(w, &j0);
        let mut tag = [0u8; 16];
        for i in 0..16 {
            tag[i] = s[i] ^ ej0[i];
        }
        tag
    }

    #[doc(hidden)]
    pub fn _block256(key: &[u8; 32], blk: &[u8; 16]) -> [u8; 16] {
        encrypt_block(&expand256(key), blk)
    }

    /// AES-128 single-block ECB encrypt — the QUIC AES header-protection cipher (RFC 9001 §5.4.3).
    pub fn aes128_ecb_block(key: &[u8; 16], block: &[u8; 16]) -> [u8; 16] {
        encrypt_block(&expand128(key), block)
    }
    /// AES-256 single-block ECB encrypt — QUIC AES-256 header protection.
    pub fn aes256_ecb_block(key: &[u8; 32], block: &[u8; 16]) -> [u8; 16] {
        encrypt_block(&expand256(key), block)
    }
}
pub mod bech32 {
    //! bech32 / bech32m (BIP-173 / BIP-350) — Bitcoin SegWit addresses, Nostr `npub`/`nsec`, Lightning.
    //! The BCH checksum + base32. Gated on the BIP-173 SegWit-v0 known address.
    const CHARSET: &[u8; 32] = b"qpzry9x8gf2tvdw0s3jn54khce6mua7l";

    fn polymod(values: &[u8]) -> u32 {
        let gen = [
            0x3b6a57b2u32,
            0x26508e6d,
            0x1ea119fa,
            0x3d4233dd,
            0x2a1462b3,
        ];
        let mut chk = 1u32;
        for &v in values {
            let b = chk >> 25;
            chk = ((chk & 0x1ffffff) << 5) ^ v as u32;
            for (i, g) in gen.iter().enumerate() {
                if (b >> i) & 1 == 1 {
                    chk ^= g;
                }
            }
        }
        chk
    }
    fn hrp_expand(hrp: &str) -> Vec<u8> {
        let mut v: Vec<u8> = hrp.bytes().map(|b| b >> 5).collect();
        v.push(0);
        v.extend(hrp.bytes().map(|b| b & 31));
        v
    }
    /// Encode `data` (already 5-bit groups) under `hrp`. `bech32m` selects the BIP-350 constant.
    pub fn encode(hrp: &str, data: &[u8], bech32m: bool) -> String {
        let mut values = hrp_expand(hrp);
        values.extend_from_slice(data);
        values.extend_from_slice(&[0; 6]);
        let cst = if bech32m { 0x2bc830a3 } else { 1 };
        let poly = polymod(&values) ^ cst;
        let mut s = format!("{hrp}1");
        for &d in data {
            s.push(CHARSET[d as usize] as char);
        }
        for i in 0..6 {
            s.push(CHARSET[((poly >> (5 * (5 - i))) & 31) as usize] as char);
        }
        s
    }
    /// 8-bit → 5-bit regrouping (`pad` for encoding). The witness/program bit conversion.
    pub fn convert_bits(data: &[u8], from: u32, to: u32, pad: bool) -> Option<Vec<u8>> {
        let (mut acc, mut bits, mut out) = (0u32, 0u32, Vec::new());
        let maxv = (1u32 << to) - 1;
        for &b in data {
            if (b as u32) >> from != 0 {
                return None;
            }
            acc = (acc << from) | b as u32;
            bits += from;
            while bits >= to {
                bits -= to;
                out.push(((acc >> bits) & maxv) as u8);
            }
        }
        if pad {
            if bits > 0 {
                out.push(((acc << (to - bits)) & maxv) as u8);
            }
        } else if bits >= from || (acc << (to - bits)) & maxv != 0 {
            return None;
        }
        Some(out)
    }
    /// A SegWit address (BIP-173/350): `witness_version` 0 → bech32, 1+ → bech32m.
    pub fn segwit_encode(hrp: &str, witness_version: u8, program: &[u8]) -> String {
        let mut data = vec![witness_version];
        data.extend(convert_bits(program, 8, 5, true).unwrap());
        encode(hrp, &data, witness_version != 0)
    }
    /// Nostr `npub` — bech32 of the 32-byte x-only public key.
    pub fn nostr_npub(pubkey: &[u8; 32]) -> String {
        encode("npub", &convert_bits(pubkey, 8, 5, true).unwrap(), false)
    }
}
pub mod blake2 {
    //! BLAKE2b (RFC 7693) — the ARX hash used by WireGuard, argon2, libsodium. The compression `G` fold,
    //! 12 rounds, 128-byte blocks. Same "fold the merge over blocks" shape as the SHA family, different
    //! round. Gated on RFC 7693 known-answers. Zero-dep.
    #![allow(clippy::needless_range_loop)]

    const IV: [u64; 8] = [
        0x6a09e667f3bcc908,
        0xbb67ae8584caa73b,
        0x3c6ef372fe94f82b,
        0xa54ff53a5f1d36f1,
        0x510e527fade682d1,
        0x9b05688c2b3e6c1f,
        0x1f83d9abfb41bd6b,
        0x5be0cd19137e2179,
    ];
    const SIGMA: [[usize; 16]; 12] = [
        [0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15],
        [14, 10, 4, 8, 9, 15, 13, 6, 1, 12, 0, 2, 11, 7, 5, 3],
        [11, 8, 12, 0, 5, 2, 15, 13, 10, 14, 3, 6, 7, 1, 9, 4],
        [7, 9, 3, 1, 13, 12, 11, 14, 2, 6, 5, 10, 4, 0, 15, 8],
        [9, 0, 5, 7, 2, 4, 10, 15, 14, 1, 11, 12, 6, 8, 3, 13],
        [2, 12, 6, 10, 0, 11, 8, 3, 4, 13, 7, 5, 15, 14, 1, 9],
        [12, 5, 1, 15, 14, 13, 4, 10, 0, 7, 6, 3, 9, 2, 8, 11],
        [13, 11, 7, 14, 12, 1, 3, 9, 5, 0, 15, 4, 8, 6, 2, 10],
        [6, 15, 14, 9, 11, 3, 0, 8, 12, 2, 13, 7, 1, 4, 10, 5],
        [10, 2, 8, 4, 7, 6, 1, 5, 15, 11, 9, 14, 3, 12, 13, 0],
        [0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15],
        [14, 10, 4, 8, 9, 15, 13, 6, 1, 12, 0, 2, 11, 7, 5, 3],
    ];

    fn g(v: &mut [u64; 16], a: usize, b: usize, c: usize, d: usize, x: u64, y: u64) {
        v[a] = v[a].wrapping_add(v[b]).wrapping_add(x);
        v[d] = (v[d] ^ v[a]).rotate_right(32);
        v[c] = v[c].wrapping_add(v[d]);
        v[b] = (v[b] ^ v[c]).rotate_right(24);
        v[a] = v[a].wrapping_add(v[b]).wrapping_add(y);
        v[d] = (v[d] ^ v[a]).rotate_right(16);
        v[c] = v[c].wrapping_add(v[d]);
        v[b] = (v[b] ^ v[c]).rotate_right(63);
    }
    fn compress(h: &mut [u64; 8], block: &[u8; 128], t: u128, last: bool) {
        let mut m = [0u64; 16];
        for i in 0..16 {
            m[i] = u64::from_le_bytes(block[i * 8..i * 8 + 8].try_into().unwrap());
        }
        let mut v = [0u64; 16];
        v[..8].copy_from_slice(h);
        v[8..].copy_from_slice(&IV);
        v[12] ^= t as u64;
        v[13] ^= (t >> 64) as u64;
        if last {
            v[14] = !v[14];
        }
        for r in 0..12 {
            let s = SIGMA[r];
            g(&mut v, 0, 4, 8, 12, m[s[0]], m[s[1]]);
            g(&mut v, 1, 5, 9, 13, m[s[2]], m[s[3]]);
            g(&mut v, 2, 6, 10, 14, m[s[4]], m[s[5]]);
            g(&mut v, 3, 7, 11, 15, m[s[6]], m[s[7]]);
            g(&mut v, 0, 5, 10, 15, m[s[8]], m[s[9]]);
            g(&mut v, 1, 6, 11, 12, m[s[10]], m[s[11]]);
            g(&mut v, 2, 7, 8, 13, m[s[12]], m[s[13]]);
            g(&mut v, 3, 4, 9, 14, m[s[14]], m[s[15]]);
        }
        for i in 0..8 {
            h[i] ^= v[i] ^ v[i + 8];
        }
    }

    /// BLAKE2b with a configurable output length (1..=64), no key. RFC 7693.
    pub fn blake2b(msg: &[u8], out_len: usize) -> Vec<u8> {
        let mut h = IV;
        h[0] ^= 0x0101_0000 | out_len as u64; // param block: no key, out_len bytes
        let mut t: u128 = 0;
        let full = if msg.is_empty() {
            0
        } else {
            (msg.len() - 1) / 128
        };
        for i in 0..full {
            t += 128;
            compress(
                &mut h,
                msg[i * 128..i * 128 + 128].try_into().unwrap(),
                t,
                false,
            );
        }
        let mut last = [0u8; 128];
        let rem = &msg[full * 128..];
        last[..rem.len()].copy_from_slice(rem);
        t += rem.len() as u128;
        compress(&mut h, &last, t, true);
        let mut out = Vec::with_capacity(out_len);
        for w in &h {
            out.extend_from_slice(&w.to_le_bytes());
        }
        out.truncate(out_len);
        out
    }
    /// BLAKE2b-512 (the default full-length digest).
    pub fn blake2b512(msg: &[u8]) -> [u8; 64] {
        let mut o = [0u8; 64];
        o.copy_from_slice(&blake2b(msg, 64));
        o
    }
}
pub mod certgen {
    //! x509 certificate ISSUANCE — the DER *encoder* (inverse of `x509::der_tlv`) + a self-signed ed25519
    //! certificate: the `rcgen` role for iroh's QUIC handshake. Zero-dep outside `hashtrinity`. Gated:
    //! openssl parses it and verifies the ed25519 self-signature.
    use crate::hashtrinity::crypto::{ed25519_pubkey, ed25519_sign};

    // ── DER encoder (also reused by `ed25519.rs`'s PKCS8/RFC 8410 masquerade — one encoder, one place) ──
    pub(crate) fn der_len(n: usize) -> Vec<u8> {
        if n < 0x80 {
            vec![n as u8]
        } else {
            let mut b = Vec::new();
            let mut m = n;
            while m > 0 {
                b.insert(0, (m & 0xff) as u8);
                m >>= 8;
            }
            let mut o = vec![0x80 | b.len() as u8];
            o.extend(b);
            o
        }
    }
    pub(crate) fn tlv(tag: u8, c: &[u8]) -> Vec<u8> {
        let mut o = vec![tag];
        o.extend(der_len(c.len()));
        o.extend_from_slice(c);
        o
    }
    pub(crate) fn seq(items: &[Vec<u8>]) -> Vec<u8> {
        let mut c = Vec::new();
        for i in items {
            c.extend_from_slice(i);
        }
        tlv(0x30, &c)
    }
    fn set(inner: &[u8]) -> Vec<u8> {
        tlv(0x31, inner)
    }
    /// INTEGER from big-endian magnitude bytes, forced non-negative (prepend 0x00 if the top bit is set).
    pub(crate) fn der_int(mag: &[u8]) -> Vec<u8> {
        let mut v = mag.to_vec();
        if v.is_empty() {
            v = vec![0];
        }
        if v[0] & 0x80 != 0 {
            v.insert(0, 0);
        }
        tlv(0x02, &v)
    }
    pub(crate) fn oid(bytes: &[u8]) -> Vec<u8> {
        tlv(0x06, bytes)
    }
    fn bitstr(data: &[u8]) -> Vec<u8> {
        let mut c = vec![0u8];
        c.extend_from_slice(data);
        tlv(0x03, &c)
    } // 0 unused bits
    fn ctx_explicit(n: u8, inner: &[u8]) -> Vec<u8> {
        tlv(0xA0 | n, inner)
    } // [n] EXPLICIT

    pub(crate) const ED25519_OID: [u8; 3] = [0x2B, 0x65, 0x70]; // 1.3.101.112
    const CN_OID: [u8; 3] = [0x55, 0x04, 0x03]; // 2.5.4.3 (commonName)

    pub(crate) fn algid_ed25519() -> Vec<u8> {
        seq(&[oid(&ED25519_OID)])
    } // no parameters for ed25519
    fn name_cn(cn: &str) -> Vec<u8> {
        let attr = seq(&[oid(&CN_OID), tlv(0x0c, cn.as_bytes())]); // UTF8String
        seq(&[set(&attr)])
    }
    fn validity() -> Vec<u8> {
        // fixed window 2020..2040, UTCTime "YYMMDDHHMMSSZ"
        seq(&[tlv(0x17, b"200101000000Z"), tlv(0x17, b"400101000000Z")])
    }
    fn spki(pubkey: &[u8; 32]) -> Vec<u8> {
        seq(&[algid_ed25519(), bitstr(pubkey)])
    }

    /// Issue a self-signed ed25519 x509 certificate (DER) for `sk`, subject/issuer CN = `cn`.
    pub fn issue_ed25519_cert(sk: &[u8; 32], cn: &str, serial: &[u8]) -> Vec<u8> {
        let pk = ed25519_pubkey(sk);
        let tbs = seq(&[
            ctx_explicit(0, &der_int(&[2])), // version v3
            der_int(serial),                 // serialNumber
            algid_ed25519(),                 // signature algorithm
            name_cn(cn),                     // issuer
            validity(),
            name_cn(cn), // subject (self-signed ⇒ == issuer)
            spki(&pk),   // subjectPublicKeyInfo
        ]);
        let sig = ed25519_sign(sk, &tbs);
        seq(&[tbs, algid_ed25519(), bitstr(&sig)]) // Certificate
    }

    const SAN_OID: [u8; 3] = [0x55, 0x1d, 0x11]; // 2.5.29.17 subjectAltName
    /// One SubjectAltName extension carrying a URI GeneralName (the SPIFFE ID).
    fn san_uri_ext(uri: &str) -> Vec<u8> {
        let general_names = seq(&[tlv(0x86, uri.as_bytes())]); // [6] uniformResourceIdentifier
        seq(&[oid(&SAN_OID), tlv(0x04, &general_names)]) // Extension { extnID, extnValue OCTET STRING }
    }
    /// Issue a self-signed ed25519 **X.509-SVID** — the SPIFFE ID in a URI SAN (SPIFFE X509-SVID §3).
    pub fn issue_ed25519_svid(sk: &[u8; 32], spiffe_id: &str, serial: &[u8]) -> Vec<u8> {
        let pk = ed25519_pubkey(sk);
        let tbs = seq(&[
            ctx_explicit(0, &der_int(&[2])),
            der_int(serial),
            algid_ed25519(),
            name_cn("SPIFFE"),
            validity(),
            name_cn("SPIFFE"),
            spki(&pk),
            ctx_explicit(3, &seq(&[san_uri_ext(spiffe_id)])), // [3] EXPLICIT extensions
        ]);
        let sig = ed25519_sign(sk, &tbs);
        seq(&[tbs, algid_ed25519(), bitstr(&sig)])
    }

    /// Issue a **CA-signed** ed25519 X.509-SVID: `workload_pk` in the SPKI, the SPIFFE ID in a URI SAN,
    /// signed by the trust-domain CA key. (The self-signed `issue_ed25519_svid` is the CA-root case.)
    pub fn issue_ed25519_svid_ca(
        ca_sk: &[u8; 32],
        workload_pk: &[u8; 32],
        spiffe_id: &str,
        serial: &[u8],
    ) -> Vec<u8> {
        let tbs = seq(&[
            ctx_explicit(0, &der_int(&[2])),
            der_int(serial),
            algid_ed25519(),
            name_cn("SPIFFE CA"),
            validity(),
            name_cn("SPIFFE"),
            spki(workload_pk),
            ctx_explicit(3, &seq(&[san_uri_ext(spiffe_id)])),
        ]);
        let sig = ed25519_sign(ca_sk, &tbs);
        seq(&[tbs, algid_ed25519(), bitstr(&sig)])
    }

    const EXT_REQ_OID: [u8; 9] = [0x2a, 0x86, 0x48, 0x86, 0xf7, 0x0d, 0x01, 0x09, 0x0e]; // 1.2.840.113549.1.9.14
    fn san_dns_ext(domains: &[&str]) -> Vec<u8> {
        let names: Vec<Vec<u8>> = domains.iter().map(|d| tlv(0x82, d.as_bytes())).collect(); // [2] dNSName
        seq(&[oid(&SAN_OID), tlv(0x04, &seq(&names))])
    }
    /// A PKCS#10 CSR (ed25519) with the domains in a SubjectAltName — the ACME `finalize` request body.
    pub fn csr_ed25519(sk: &[u8; 32], domains: &[&str]) -> Vec<u8> {
        let pk = ed25519_pubkey(sk);
        let ext_req = seq(&[oid(&EXT_REQ_OID), tlv(0x31, &seq(&[san_dns_ext(domains)]))]); // extensionRequest attr
        let cri = seq(&[
            der_int(&[0]),       // version 0
            seq(&[]),            // subject: empty (ACME uses the SAN)
            spki(&pk),           // subjectPKInfo
            tlv(0xA0, &ext_req), // [0] attributes
        ]);
        let sig = ed25519_sign(sk, &cri);
        seq(&[cri, algid_ed25519(), bitstr(&sig)])
    }
}
pub mod keccak {
    //! SHA-3 / Keccak (FIPS 202) — the sponge. Distinct from the Merkle–Damgård `md` fold: absorb XORs
    //! blocks into a 1600-bit state and permutes (the merge), squeeze reads it out (the get). SHA3-256/512,
    //! the SHAKE XOFs, and Keccak-256 (Ethereum's pre-standard variant — same permutation, `0x01` domain).
    //! Gated on FIPS 202 known-answers. Zero-dep.

    const RC: [u64; 24] = [
        0x0000000000000001,
        0x0000000000008082,
        0x800000000000808a,
        0x8000000080008000,
        0x000000000000808b,
        0x0000000080000001,
        0x8000000080008081,
        0x8000000000008009,
        0x000000000000008a,
        0x0000000000000088,
        0x0000000080008009,
        0x000000008000000a,
        0x000000008000808b,
        0x800000000000008b,
        0x8000000000008089,
        0x8000000000008003,
        0x8000000000008002,
        0x8000000000000080,
        0x000000000000800a,
        0x800000008000000a,
        0x8000000080008081,
        0x8000000000008080,
        0x0000000080000001,
        0x8000000080008008,
    ];
    const RHO: [u32; 24] = [
        1, 3, 6, 10, 15, 21, 28, 36, 45, 55, 2, 14, 27, 41, 56, 8, 25, 43, 62, 18, 39, 61, 20, 44,
    ];
    const PI: [usize; 24] = [
        10, 7, 11, 17, 18, 3, 5, 16, 8, 21, 24, 4, 15, 23, 19, 13, 12, 2, 20, 14, 22, 9, 6, 1,
    ];

    /// The Keccak-f[1600] permutation — 24 rounds of θ ρ π χ ι over the 5×5 lane state.
    fn keccakf(a: &mut [u64; 25]) {
        let mut bc = [0u64; 5];
        for round in 0..24 {
            // θ
            for i in 0..5 {
                bc[i] = a[i] ^ a[i + 5] ^ a[i + 10] ^ a[i + 15] ^ a[i + 20];
            }
            for i in 0..5 {
                let t = bc[(i + 4) % 5] ^ bc[(i + 1) % 5].rotate_left(1);
                for j in (0..25).step_by(5) {
                    a[j + i] ^= t;
                }
            }
            // ρ + π
            let mut t = a[1];
            for i in 0..24 {
                let j = PI[i];
                let tmp = a[j];
                a[j] = t.rotate_left(RHO[i]);
                t = tmp;
            }
            // χ
            for j in (0..25).step_by(5) {
                for i in 0..5 {
                    bc[i] = a[j + i];
                }
                for i in 0..5 {
                    a[j + i] ^= (!bc[(i + 1) % 5]) & bc[(i + 2) % 5];
                }
            }
            // ι
            a[0] ^= RC[round];
        }
    }

    /// The sponge: absorb `input` at `rate` bytes with domain separator `delim`, squeeze `out.len()` bytes.
    fn sponge(input: &[u8], rate: usize, delim: u8, out: &mut [u8]) {
        let mut a = [0u64; 25];
        let mut chunks = input.chunks_exact(rate);
        for block in chunks.by_ref() {
            for i in 0..rate / 8 {
                a[i] ^= u64::from_le_bytes(block[i * 8..i * 8 + 8].try_into().unwrap());
            }
            keccakf(&mut a);
        }
        let rem = chunks.remainder();
        let mut last = [0u8; 200];
        last[..rem.len()].copy_from_slice(rem);
        last[rem.len()] ^= delim; // domain separator (0x06 SHA3, 0x1f SHAKE, 0x01 Keccak)
        last[rate - 1] ^= 0x80; // pad10*1 final bit
        for i in 0..rate / 8 {
            a[i] ^= u64::from_le_bytes(last[i * 8..i * 8 + 8].try_into().unwrap());
        }
        keccakf(&mut a);
        let mut done = 0;
        loop {
            let take = (out.len() - done).min(rate);
            for i in 0..take {
                out[done + i] = (a[i / 8] >> (8 * (i % 8))) as u8;
            }
            done += take;
            if done >= out.len() {
                break;
            }
            keccakf(&mut a);
        }
    }

    /// SHA3-256 (FIPS 202) — rate 136, domain `0x06`.
    pub fn sha3_256(msg: &[u8]) -> [u8; 32] {
        let mut o = [0u8; 32];
        sponge(msg, 136, 0x06, &mut o);
        o
    }
    /// SHA3-512 (FIPS 202) — rate 72.
    pub fn sha3_512(msg: &[u8]) -> [u8; 64] {
        let mut o = [0u8; 64];
        sponge(msg, 72, 0x06, &mut o);
        o
    }
    /// Keccak-256 — Ethereum's pre-standard SHA-3 (domain `0x01`).
    pub fn keccak256(msg: &[u8]) -> [u8; 32] {
        let mut o = [0u8; 32];
        sponge(msg, 136, 0x01, &mut o);
        o
    }
    /// SHAKE128 XOF — rate 168, domain `0x1f`, arbitrary output length.
    pub fn shake128(msg: &[u8], out_len: usize) -> Vec<u8> {
        let mut o = vec![0u8; out_len];
        sponge(msg, 168, 0x1f, &mut o);
        o
    }
    /// SHAKE256 XOF — rate 136.
    pub fn shake256(msg: &[u8], out_len: usize) -> Vec<u8> {
        let mut o = vec![0u8; out_len];
        sponge(msg, 136, 0x1f, &mut o);
        o
    }
}
pub mod mlkem {
    //! ML-KEM-768 (FIPS 203) — the post-quantum KEM now shipping in TLS 1.3's `X25519MLKEM768` hybrid.
    //! Genuinely new machinery vs the rest of the crate: lattice arithmetic in R_q = Z₃₃₂₉[X]/(X²⁵⁶+1),
    //! the NTT, CBD sampling, and the Fujisaki–Okamoto transform. Hashing is SHA3/SHAKE (this crate's
    //! keccak). Gated against openssl's ML-KEM-768 (interop, both directions). Zero-dep.
    #![allow(clippy::needless_range_loop)]
    use crate::hashtrinity::crypto::keccak::{sha3_256, sha3_512, shake128, shake256};
    use std::sync::OnceLock;

    const N: usize = 256;
    const Q: i32 = 3329;
    const K: usize = 3; // ML-KEM-768
    const ETA1: usize = 2;
    const ETA2: usize = 2;
    const DU: usize = 10;
    const DV: usize = 4;
    type Poly = [i32; N];

    fn modq(x: i32) -> i32 {
        let r = x % Q;
        if r < 0 {
            r + Q
        } else {
            r
        }
    }
    fn pow_mod(b: i64, mut e: u32) -> i32 {
        let mut r = 1i64;
        let mut base = b % Q as i64;
        while e > 0 {
            if e & 1 == 1 {
                r = r * base % Q as i64;
            }
            base = base * base % Q as i64;
            e >>= 1;
        }
        r as i32
    }
    fn bitrev7(x: usize) -> usize {
        let mut r = 0;
        for i in 0..7 {
            r |= ((x >> i) & 1) << (6 - i);
        }
        r
    }
    fn tables() -> &'static ([i32; 128], [i32; 128]) {
        static T: OnceLock<([i32; 128], [i32; 128])> = OnceLock::new();
        T.get_or_init(|| {
            let mut z = [0i32; 128];
            let mut g = [0i32; 128];
            for i in 0..128 {
                let br = bitrev7(i) as u32;
                z[i] = pow_mod(17, br);
                g[i] = pow_mod(17, 2 * br + 1);
            }
            (z, g)
        })
    }

    fn ntt(f: &mut Poly) {
        let (z, _) = tables();
        let mut i = 1;
        let mut len = 128;
        while len >= 2 {
            let mut start = 0;
            while start < N {
                let zeta = z[i];
                i += 1;
                for j in start..start + len {
                    let t = modq(zeta * f[j + len]);
                    f[j + len] = modq(f[j] - t);
                    f[j] = modq(f[j] + t);
                }
                start += 2 * len;
            }
            len >>= 1;
        }
    }
    fn intt(f: &mut Poly) {
        let (z, _) = tables();
        let mut i = 127;
        let mut len = 2;
        while len <= 128 {
            let mut start = 0;
            while start < N {
                let zeta = z[i];
                i -= 1;
                for j in start..start + len {
                    let t = f[j];
                    f[j] = modq(t + f[j + len]);
                    f[j + len] = modq(zeta * (f[j + len] - t));
                }
                start += 2 * len;
            }
            len <<= 1;
        }
        for x in f.iter_mut() {
            *x = modq(*x * 3303);
        } // 128⁻¹ mod q
    }
    fn mul_ntts(f: &Poly, g: &Poly) -> Poly {
        let (_, gam) = tables();
        let mut h = [0i32; N];
        for i in 0..128 {
            let (a0, a1, b0, b1) = (f[2 * i], f[2 * i + 1], g[2 * i], g[2 * i + 1]);
            h[2 * i] = modq(modq(a0 * b0) + modq(modq(a1 * b1) * gam[i]));
            h[2 * i + 1] = modq(a0 * b1 + a1 * b0);
        }
        h
    }
    fn padd(a: &Poly, b: &Poly) -> Poly {
        let mut r = [0i32; N];
        for i in 0..N {
            r[i] = modq(a[i] + b[i]);
        }
        r
    }

    fn cbd(bytes: &[u8], eta: usize) -> Poly {
        let bit = |i: usize| ((bytes[i / 8] >> (i % 8)) & 1) as i32;
        let mut f = [0i32; N];
        for i in 0..N {
            let mut x = 0;
            let mut y = 0;
            for j in 0..eta {
                x += bit(2 * i * eta + j);
            }
            for j in 0..eta {
                y += bit(2 * i * eta + eta + j);
            }
            f[i] = modq(x - y);
        }
        f
    }
    fn compress(x: i32, d: usize) -> i32 {
        let num = (modq(x) as i64) << d;
        (((num + Q as i64 / 2) / Q as i64) as i32) & ((1 << d) - 1)
    }
    fn decompress(y: i32, d: usize) -> i32 {
        (((y as i64 * Q as i64) + (1 << (d - 1))) >> d) as i32
    }
    fn compress_poly(f: &Poly, d: usize) -> Poly {
        let mut r = [0i32; N];
        for i in 0..N {
            r[i] = compress(f[i], d);
        }
        r
    }
    fn decompress_poly(f: &Poly, d: usize) -> Poly {
        let mut r = [0i32; N];
        for i in 0..N {
            r[i] = decompress(f[i], d);
        }
        r
    }

    fn byte_encode(f: &Poly, d: usize) -> Vec<u8> {
        let mut out = vec![0u8; 32 * d];
        let mut bp = 0;
        for i in 0..N {
            let v = f[i] as u32;
            for b in 0..d {
                if (v >> b) & 1 == 1 {
                    out[bp / 8] |= 1 << (bp % 8);
                }
                bp += 1;
            }
        }
        out
    }
    fn byte_decode(bytes: &[u8], d: usize) -> Poly {
        let mut f = [0i32; N];
        let mut bp = 0;
        for i in 0..N {
            let mut v = 0u32;
            for b in 0..d {
                v |= (((bytes[bp / 8] >> (bp % 8)) & 1) as u32) << b;
                bp += 1;
            }
            f[i] = if d == 12 {
                (v % Q as u32) as i32
            } else {
                v as i32
            };
        }
        f
    }
    fn sample_ntt(seed: &[u8]) -> Poly {
        let mut a = [0i32; N];
        let mut i = 0;
        let mut want = 504;
        let mut buf = shake128(seed, want);
        let mut pos = 0;
        while i < N {
            if pos + 3 > buf.len() {
                want *= 2;
                buf = shake128(seed, want);
            }
            let (b0, b1, b2) = (buf[pos] as i32, buf[pos + 1] as i32, buf[pos + 2] as i32);
            pos += 3;
            let d1 = b0 + 256 * (b1 & 0xF);
            let d2 = (b1 >> 4) + 16 * b2;
            if d1 < Q {
                a[i] = d1;
                i += 1;
            }
            if d2 < Q && i < N {
                a[i] = d2;
                i += 1;
            }
        }
        a
    }
    fn gen_matrix(rho: &[u8]) -> Vec<Vec<Poly>> {
        let mut a = vec![vec![[0i32; N]; K]; K];
        for i in 0..K {
            for j in 0..K {
                let mut s = rho.to_vec();
                s.push(j as u8);
                s.push(i as u8);
                a[i][j] = sample_ntt(&s);
            }
        }
        a
    }
    fn prf(eta: usize, s: &[u8], b: u8) -> Vec<u8> {
        let mut inp = s.to_vec();
        inp.push(b);
        shake256(&inp, 64 * eta)
    }

    fn kpke_keygen(d: &[u8; 32]) -> (Vec<u8>, Vec<u8>) {
        let mut gin = d.to_vec();
        gin.push(K as u8);
        let g = sha3_512(&gin);
        let (rho, sigma) = (&g[..32], &g[32..]);
        let a = gen_matrix(rho);
        let (mut s, mut e) = ([[0i32; N]; K], [[0i32; N]; K]);
        let mut n = 0u8;
        for i in 0..K {
            s[i] = cbd(&prf(ETA1, sigma, n), ETA1);
            n += 1;
        }
        for i in 0..K {
            e[i] = cbd(&prf(ETA1, sigma, n), ETA1);
            n += 1;
        }
        for i in 0..K {
            ntt(&mut s[i]);
            ntt(&mut e[i]);
        }
        let mut ek = Vec::new();
        for i in 0..K {
            let mut acc = [0i32; N];
            for j in 0..K {
                acc = padd(&acc, &mul_ntts(&a[i][j], &s[j]));
            }
            ek.extend(byte_encode(&padd(&acc, &e[i]), 12));
        }
        ek.extend_from_slice(rho);
        let mut dk = Vec::new();
        for i in 0..K {
            dk.extend(byte_encode(&s[i], 12));
        }
        (ek, dk)
    }
    fn kpke_encrypt(ek: &[u8], m: &[u8; 32], r: &[u8; 32]) -> Vec<u8> {
        let mut t = [[0i32; N]; K];
        for i in 0..K {
            t[i] = byte_decode(&ek[384 * i..384 * (i + 1)], 12);
        }
        let a = gen_matrix(&ek[384 * K..384 * K + 32]);
        let (mut y, mut e1) = ([[0i32; N]; K], [[0i32; N]; K]);
        let mut n = 0u8;
        for i in 0..K {
            y[i] = cbd(&prf(ETA1, r, n), ETA1);
            n += 1;
        }
        for i in 0..K {
            e1[i] = cbd(&prf(ETA2, r, n), ETA2);
            n += 1;
        }
        let e2 = cbd(&prf(ETA2, r, n), ETA2);
        for i in 0..K {
            ntt(&mut y[i]);
        }
        let mut c = Vec::new();
        for i in 0..K {
            let mut acc = [0i32; N];
            for j in 0..K {
                acc = padd(&acc, &mul_ntts(&a[j][i], &y[j]));
            } // Aᵀ
            intt(&mut acc);
            c.extend(byte_encode(&compress_poly(&padd(&acc, &e1[i]), DU), DU));
        }
        let mut acc = [0i32; N];
        for j in 0..K {
            acc = padd(&acc, &mul_ntts(&t[j], &y[j]));
        }
        intt(&mut acc);
        let mut mu = [0i32; N];
        for i in 0..N {
            mu[i] = decompress(((m[i / 8] >> (i % 8)) & 1) as i32, 1);
        }
        let v = padd(&padd(&acc, &e2), &mu);
        c.extend(byte_encode(&compress_poly(&v, DV), DV));
        c
    }
    fn kpke_decrypt(dk: &[u8], c: &[u8]) -> [u8; 32] {
        let mut u = [[0i32; N]; K];
        for i in 0..K {
            u[i] = decompress_poly(&byte_decode(&c[32 * DU * i..32 * DU * (i + 1)], DU), DU);
        }
        let v = decompress_poly(&byte_decode(&c[32 * DU * K..], DV), DV);
        let mut s = [[0i32; N]; K];
        for i in 0..K {
            s[i] = byte_decode(&dk[384 * i..384 * (i + 1)], 12);
        }
        for i in 0..K {
            ntt(&mut u[i]);
        }
        let mut acc = [0i32; N];
        for j in 0..K {
            acc = padd(&acc, &mul_ntts(&s[j], &u[j]));
        }
        intt(&mut acc);
        let mut m = [0u8; 32];
        for i in 0..N {
            if compress(modq(v[i] - acc[i]), 1) & 1 == 1 {
                m[i / 8] |= 1 << (i % 8);
            }
        }
        m
    }

    /// ML-KEM-768 deterministic key generation from seeds `d`, `z` (FIPS 203 §7.1). Returns `(ek, dk)`
    /// (1184 / 2400 bytes).
    pub fn keygen(d: &[u8; 32], z: &[u8; 32]) -> (Vec<u8>, Vec<u8>) {
        let (ek, dk_pke) = kpke_keygen(d);
        let mut dk = dk_pke;
        dk.extend_from_slice(&ek);
        dk.extend_from_slice(&sha3_256(&ek));
        dk.extend_from_slice(z);
        (ek, dk)
    }
    /// ML-KEM-768 encapsulation, deterministic in the 32-byte message `m`. Returns `(shared_key, ciphertext)`.
    pub fn encaps(ek: &[u8], m: &[u8; 32]) -> (Vec<u8>, Vec<u8>) {
        let mut gin = m.to_vec();
        gin.extend_from_slice(&sha3_256(ek));
        let g = sha3_512(&gin);
        let mut r = [0u8; 32];
        r.copy_from_slice(&g[32..]);
        (g[..32].to_vec(), kpke_encrypt(ek, m, &r))
    }
    /// ML-KEM-768 decapsulation with the FO implicit-reject (returns `J(z‖c)` on a bad ciphertext).
    pub fn decaps(dk: &[u8], c: &[u8]) -> Vec<u8> {
        let dk_pke = &dk[..384 * K];
        let ek = &dk[384 * K..768 * K + 32];
        let h = &dk[768 * K + 32..768 * K + 64];
        let z = &dk[768 * K + 64..768 * K + 96];
        let m = kpke_decrypt(dk_pke, c);
        let mut gin = m.to_vec();
        gin.extend_from_slice(h);
        let g = sha3_512(&gin);
        let mut r = [0u8; 32];
        r.copy_from_slice(&g[32..]);
        let mut jin = z.to_vec();
        jin.extend_from_slice(c);
        let kbar = shake256(&jin, 32);
        if c == kpke_encrypt(ek, &m, &r) {
            g[..32].to_vec()
        } else {
            kbar
        }
    }
}
pub mod ripemd160 {
    //! RIPEMD-160 — the hash in Bitcoin's `Hash160` (RIPEMD160∘SHA256, the address hash). Two parallel
    //! ARX lines, 80 steps each, 64-byte little-endian blocks. Gated on the RIPEMD-160 known-answers.
    #![allow(clippy::needless_range_loop, clippy::too_many_arguments)]

    const RL: [usize; 80] = [
        0, 1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12, 13, 14, 15, 7, 4, 13, 1, 10, 6, 15, 3, 12, 0, 9, 5,
        2, 14, 11, 8, 3, 10, 14, 4, 9, 15, 8, 1, 2, 7, 0, 6, 13, 11, 5, 12, 1, 9, 11, 10, 0, 8, 12, 4,
        13, 3, 7, 15, 14, 5, 6, 2, 4, 0, 5, 9, 7, 12, 2, 10, 14, 1, 3, 8, 11, 6, 15, 13,
    ];
    const RR: [usize; 80] = [
        5, 14, 7, 0, 9, 2, 11, 4, 13, 6, 15, 8, 1, 10, 3, 12, 6, 11, 3, 7, 0, 13, 5, 10, 14, 15, 8, 12,
        4, 9, 1, 2, 15, 5, 1, 3, 7, 14, 6, 9, 11, 8, 12, 2, 10, 0, 4, 13, 8, 6, 4, 1, 3, 11, 15, 0, 5,
        12, 2, 13, 9, 7, 10, 14, 12, 15, 10, 4, 1, 5, 8, 7, 6, 2, 13, 14, 0, 3, 9, 11,
    ];
    const SL: [u32; 80] = [
        11, 14, 15, 12, 5, 8, 7, 9, 11, 13, 14, 15, 6, 7, 9, 8, 7, 6, 8, 13, 11, 9, 7, 15, 7, 12, 15,
        9, 11, 7, 13, 12, 11, 13, 6, 7, 14, 9, 13, 15, 14, 8, 13, 6, 5, 12, 7, 5, 11, 12, 14, 15, 14,
        15, 9, 8, 9, 14, 5, 6, 8, 6, 5, 12, 9, 15, 5, 11, 6, 8, 13, 12, 5, 12, 13, 14, 11, 8, 5, 6,
    ];
    const SR: [u32; 80] = [
        8, 9, 9, 11, 13, 15, 15, 5, 7, 7, 8, 11, 14, 14, 12, 6, 9, 13, 15, 7, 12, 8, 9, 11, 7, 7, 12,
        7, 6, 15, 13, 11, 9, 7, 15, 11, 8, 6, 6, 14, 12, 13, 5, 14, 13, 13, 7, 5, 15, 5, 8, 11, 14, 14,
        6, 14, 6, 9, 12, 9, 12, 5, 15, 8, 8, 5, 12, 9, 12, 5, 14, 6, 8, 13, 6, 5, 15, 13, 11, 11,
    ];
    const KL: [u32; 5] = [0x00000000, 0x5a827999, 0x6ed9eba1, 0x8f1bbcdc, 0xa953fd4e];
    const KR: [u32; 5] = [0x50a28be6, 0x5c4dd124, 0x6d703ef3, 0x7a6d76e9, 0x00000000];

    fn f(j: usize, x: u32, y: u32, z: u32) -> u32 {
        match j / 16 {
            0 => x ^ y ^ z,
            1 => (x & y) | (!x & z),
            2 => (x | !y) ^ z,
            3 => (x & z) | (y & !z),
            _ => x ^ (y | !z),
        }
    }

    fn compress(h: &mut [u32; 5], block: &[u8; 64]) {
        let mut m = [0u32; 16];
        for i in 0..16 {
            m[i] = u32::from_le_bytes(block[i * 4..i * 4 + 4].try_into().unwrap());
        }
        let (mut al, mut bl, mut cl, mut dl, mut el) = (h[0], h[1], h[2], h[3], h[4]);
        let (mut ar, mut br, mut cr, mut dr, mut er) = (h[0], h[1], h[2], h[3], h[4]);
        for j in 0..80 {
            let t = al
                .wrapping_add(f(j, bl, cl, dl))
                .wrapping_add(m[RL[j]])
                .wrapping_add(KL[j / 16])
                .rotate_left(SL[j])
                .wrapping_add(el);
            al = el;
            el = dl;
            dl = cl.rotate_left(10);
            cl = bl;
            bl = t;
            let t = ar
                .wrapping_add(f(79 - j, br, cr, dr))
                .wrapping_add(m[RR[j]])
                .wrapping_add(KR[j / 16])
                .rotate_left(SR[j])
                .wrapping_add(er);
            ar = er;
            er = dr;
            dr = cr.rotate_left(10);
            cr = br;
            br = t;
        }
        let t = h[1].wrapping_add(cl).wrapping_add(dr);
        h[1] = h[2].wrapping_add(dl).wrapping_add(er);
        h[2] = h[3].wrapping_add(el).wrapping_add(ar);
        h[3] = h[4].wrapping_add(al).wrapping_add(br);
        h[4] = h[0].wrapping_add(bl).wrapping_add(cr);
        h[0] = t;
    }

    /// RIPEMD-160 of `msg` (little-endian MD padding).
    pub fn ripemd160(msg: &[u8]) -> [u8; 20] {
        let mut h: [u32; 5] = [0x67452301, 0xefcdab89, 0x98badcfe, 0x10325476, 0xc3d2e1f0];
        let mut m = msg.to_vec();
        let bitlen = (msg.len() as u64).wrapping_mul(8);
        m.push(0x80);
        while m.len() % 64 != 56 {
            m.push(0);
        }
        m.extend_from_slice(&bitlen.to_le_bytes());
        for block in m.chunks_exact(64) {
            compress(&mut h, block.try_into().unwrap());
        }
        let mut o = [0u8; 20];
        for i in 0..5 {
            o[i * 4..i * 4 + 4].copy_from_slice(&h[i].to_le_bytes());
        }
        o
    }
    /// Bitcoin `Hash160` — RIPEMD160(SHA256(x)), the public-key/script hash.
    pub fn hash160(data: &[u8]) -> [u8; 20] {
        ripemd160(&crate::hashtrinity::crypto::sha256(data))
    }
}
pub mod secp256k1 {
    //! secp256k1 (SEC 2) — the Bitcoin/Ethereum curve. ECDSA sign (RFC 6979) + verify + **public-key
    //! recovery** (`ecrecover`). Same group-merge as the NIST curves, but `y² = x³ + 7` (a=0), so the
    //! Jacobian doubling drops the `a·Z⁴` term. Gated on a python-generated known-answer.
    #![allow(clippy::needless_range_loop)]

    type U = [u64; 4];
    const P: U = [
        0xfffffffefffffc2f,
        0xffffffffffffffff,
        0xffffffffffffffff,
        0xffffffffffffffff,
    ];
    const N: U = [
        0xbfd25e8cd0364141,
        0xbaaedce6af48a03b,
        0xfffffffffffffffe,
        0xffffffffffffffff,
    ];
    const GX: U = [
        0x59f2815b16f81798,
        0x029bfcdb2dce28d9,
        0x55a06295ce870b07,
        0x79be667ef9dcbbac,
    ];
    const GY: U = [
        0x9c47d08ffb10d4b8,
        0xfd17b448a6855419,
        0x5da4fbfc0e1108a8,
        0x483ada7726a3c465,
    ];

    fn from_be(b: &[u8]) -> U {
        let mut r = [0u64; 4];
        for i in 0..4 {
            r[i] = u64::from_be_bytes(b[24 - i * 8..32 - i * 8].try_into().unwrap());
        }
        r
    }
    fn to_be(u: &U) -> [u8; 32] {
        let mut b = [0u8; 32];
        for i in 0..4 {
            b[24 - i * 8..32 - i * 8].copy_from_slice(&u[i].to_be_bytes());
        }
        b
    }
    fn is_zero(a: &U) -> bool {
        a == &[0, 0, 0, 0]
    }
    fn ge5(a: &[u64; 5], m: &[u64; 5]) -> bool {
        for i in (0..5).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }
    fn sub5(a: &mut [u64; 5], m: &[u64; 5]) {
        let mut br = 0i128;
        for i in 0..5 {
            let v = a[i] as i128 - m[i] as i128 - br;
            if v < 0 {
                a[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                a[i] = v as u64;
                br = 0;
            }
        }
    }
    fn ge4(a: &U, m: &U) -> bool {
        for i in (0..4).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }
    fn mul512(a: &U, b: &U) -> [u64; 8] {
        let mut p = [0u64; 8];
        for i in 0..4 {
            let mut cr = 0u128;
            for j in 0..4 {
                let t = a[i] as u128 * b[j] as u128 + p[i + j] as u128 + cr;
                p[i + j] = t as u64;
                cr = t >> 64;
            }
            let mut k = i + 4;
            while cr != 0 && k < 8 {
                let t = p[k] as u128 + cr;
                p[k] = t as u64;
                cr = t >> 64;
                k += 1;
            }
        }
        p
    }
    fn mod_gen(x: &[u64; 8], m: &U) -> U {
        let m5 = [m[0], m[1], m[2], m[3], 0];
        let mut rem = [0u64; 5];
        for i in (0..512).rev() {
            let bit = (x[i / 64] >> (i % 64)) & 1;
            let mut c = bit;
            for l in rem.iter_mut() {
                let nc = *l >> 63;
                *l = (*l << 1) | c;
                c = nc;
            }
            if ge5(&rem, &m5) {
                sub5(&mut rem, &m5);
            }
        }
        [rem[0], rem[1], rem[2], rem[3]]
    }
    fn mulmod(a: &U, b: &U, m: &U) -> U {
        mod_gen(&mul512(a, b), m)
    }
    fn addmod(a: &U, b: &U, m: &U) -> U {
        let mut s = [0u64; 5];
        let mut c = 0u128;
        for i in 0..4 {
            let t = a[i] as u128 + b[i] as u128 + c;
            s[i] = t as u64;
            c = t >> 64;
        }
        s[4] = c as u64;
        let m5 = [m[0], m[1], m[2], m[3], 0];
        if ge5(&s, &m5) {
            sub5(&mut s, &m5);
        }
        [s[0], s[1], s[2], s[3]]
    }
    fn submod(a: &U, b: &U, m: &U) -> U {
        if ge4(a, b) {
            let mut r = *a;
            let mut br = 0i128;
            for i in 0..4 {
                let v = r[i] as i128 - b[i] as i128 - br;
                if v < 0 {
                    r[i] = (v + (1i128 << 64)) as u64;
                    br = 1;
                } else {
                    r[i] = v as u64;
                    br = 0;
                }
            }
            r
        } else {
            addmod(a, &submod(m, b, m), m)
        }
    }
    fn sub_small(a: &U, k: u64) -> U {
        let mut r = *a;
        let mut br = k as i128;
        for i in 0..4 {
            let v = r[i] as i128 - br;
            if v < 0 {
                r[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                r[i] = v as u64;
                br = 0;
            }
        }
        r
    }
    fn powmod(a: &U, e: &U, m: &U) -> U {
        let mut r = [1u64, 0, 0, 0];
        let mut base = *a;
        for i in 0..256 {
            if (e[i / 64] >> (i % 64)) & 1 == 1 {
                r = mulmod(&r, &base, m);
            }
            base = mulmod(&base, &base, m);
        }
        r
    }
    fn invmod(a: &U, m: &U) -> U {
        powmod(a, &sub_small(m, 2), m)
    }
    /// Right-shift by 1 (carry flows high→low limb).
    fn shr1(a: &U) -> U {
        let mut r = *a;
        let mut c = 0u64;
        for i in (0..4).rev() {
            let nv = (r[i] >> 1) | (c << 63);
            c = r[i] & 1;
            r[i] = nv;
        }
        r
    }

    #[derive(Clone, Copy)]
    struct Jac {
        x: U,
        y: U,
        z: U,
    }
    fn jinf() -> Jac {
        Jac {
            x: [1, 0, 0, 0],
            y: [1, 0, 0, 0],
            z: [0, 0, 0, 0],
        }
    }
    fn fmul(a: &U, b: &U) -> U {
        mulmod(a, b, &P)
    }
    fn fsq(a: &U) -> U {
        mulmod(a, a, &P)
    }
    fn fadd(a: &U, b: &U) -> U {
        addmod(a, b, &P)
    }
    fn fsub(a: &U, b: &U) -> U {
        submod(a, b, &P)
    }

    fn jdouble(p: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *p;
        }
        let a = fsq(&p.x); // X²
        let b = fsq(&p.y); // Y²
        let c = fsq(&b); // Y⁴
        let d = {
            let t = fsub(&fsq(&fadd(&p.x, &b)), &fadd(&a, &c));
            fadd(&t, &t)
        }; // 2((X+B)²-A-C)
        let e = fadd(&fadd(&a, &a), &a); // 3X²  (a=0)
        let x3 = fsub(&fsq(&e), &fadd(&d, &d));
        let c8 = {
            let t = fadd(&c, &c);
            let t = fadd(&t, &t);
            fadd(&t, &t)
        };
        let y3 = fsub(&fmul(&e, &fsub(&d, &x3)), &c8);
        let z3 = {
            let yz = fmul(&p.y, &p.z);
            fadd(&yz, &yz)
        };
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jadd(p: &Jac, q: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *q;
        }
        if is_zero(&q.z) {
            return *p;
        }
        let z1z1 = fsq(&p.z);
        let z2z2 = fsq(&q.z);
        let u1 = fmul(&p.x, &z2z2);
        let u2 = fmul(&q.x, &z1z1);
        let s1 = fmul(&fmul(&p.y, &q.z), &z2z2);
        let s2 = fmul(&fmul(&q.y, &p.z), &z1z1);
        if u1 == u2 {
            if s1 == s2 {
                return jdouble(p);
            } else {
                return jinf();
            }
        }
        let h = fsub(&u2, &u1);
        let i = fsq(&fadd(&h, &h));
        let j = fmul(&h, &i);
        let rr = fadd(&fsub(&s2, &s1), &fsub(&s2, &s1));
        let v = fmul(&u1, &i);
        let x3 = fsub(&fsub(&fsq(&rr), &j), &fadd(&v, &v));
        let y3 = fsub(&fmul(&rr, &fsub(&v, &x3)), &fmul(&fadd(&s1, &s1), &j));
        let z3 = fmul(&fsub(&fsub(&fsq(&fadd(&p.z, &q.z)), &z1z1), &z2z2), &h);
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jscalar(k: &U, p: &Jac) -> Jac {
        let mut r = jinf();
        for i in (0..256).rev() {
            r = jdouble(&r);
            if (k[i / 64] >> (i % 64)) & 1 == 1 {
                r = jadd(&r, p);
            }
        }
        r
    }
    fn affine(p: &Jac) -> Option<(U, U)> {
        if is_zero(&p.z) {
            return None;
        }
        let zi = invmod(&p.z, &P);
        let zi2 = fsq(&zi);
        Some((fmul(&p.x, &zi2), fmul(&fmul(&p.y, &zi2), &zi)))
    }

    fn hmac(k: &[u8], d: &[u8]) -> [u8; 32] {
        crate::hashtrinity::crypto::hmac_sha256(k, d)
    }
    fn rfc6979_k(xo: &[u8; 32], ho: &[u8; 32]) -> U {
        let mut v = [1u8; 32];
        let mut k = [0u8; 32];
        let seed = |flag: u8, k: &[u8; 32], v: &[u8; 32]| {
            let mut b = v.to_vec();
            b.push(flag);
            b.extend_from_slice(xo);
            b.extend_from_slice(ho);
            hmac(k, &b)
        };
        k = seed(0, &k, &v);
        v = hmac(&k, &v);
        k = seed(1, &k, &v);
        v = hmac(&k, &v);
        loop {
            v = hmac(&k, &v);
            let c = from_be(&v);
            if !is_zero(&c) && !ge4(&c, &N) {
                return c;
            }
            let mut b = v.to_vec();
            b.push(0);
            k = hmac(&k, &b);
            v = hmac(&k, &v);
        }
    }

    fn e_mod(hash: &[u8; 32]) -> U {
        let mut he = [0u64; 8];
        he[..4].copy_from_slice(&from_be(hash));
        mod_gen(&he, &N)
    }

    /// secp256k1 pubkey (uncompressed `x‖y`, 64B) from a 32-byte secret.
    pub fn pubkey(secret: &[u8; 32]) -> [u8; 64] {
        let (x, y) = affine(&jscalar(
            &from_be(secret),
            &Jac {
                x: GX,
                y: GY,
                z: [1, 0, 0, 0],
            },
        ))
        .unwrap();
        let mut o = [0u8; 64];
        o[..32].copy_from_slice(&to_be(&x));
        o[32..].copy_from_slice(&to_be(&y));
        o
    }

    /// secp256k1 ECDSA sign (RFC 6979). Returns `(r‖s, recovery_id)` — `s` low-normalized (BIP-62).
    pub fn sign(secret: &[u8; 32], hash: &[u8; 32]) -> ([u8; 64], u8) {
        let d = from_be(secret);
        let e = e_mod(hash);
        let k = rfc6979_k(secret, &to_be(&e));
        let (rx, ry) = affine(&jscalar(
            &k,
            &Jac {
                x: GX,
                y: GY,
                z: [1, 0, 0, 0],
            },
        ))
        .unwrap();
        let mut rx8 = [0u64; 8];
        rx8[..4].copy_from_slice(&rx);
        let r = mod_gen(&rx8, &N);
        let s = mulmod(&invmod(&k, &N), &addmod(&e, &mulmod(&r, &d, &N), &N), &N);
        // low-s normalization: if s > n/2, s = n - s and flip the parity bit
        let (s, odd_flip) = if ge4(&s, &shr1(&N)) {
            (submod(&[0, 0, 0, 0], &s, &N), 1)
        } else {
            (s, 0)
        };
        let recid = ((ry[0] & 1) as u8) ^ odd_flip;
        let mut sig = [0u8; 64];
        sig[..32].copy_from_slice(&to_be(&r));
        sig[32..].copy_from_slice(&to_be(&s));
        (sig, recid)
    }

    /// secp256k1 ECDSA verify: `pubkey` = `x‖y` (64B), `sig` = `r‖s` (64B).
    pub fn verify(pubkey: &[u8; 64], hash: &[u8; 32], sig: &[u8; 64]) -> bool {
        let (qx, qy) = (from_be(&pubkey[..32]), from_be(&pubkey[32..]));
        let (r, s) = (from_be(&sig[..32]), from_be(&sig[32..]));
        if is_zero(&r) || ge4(&r, &N) || is_zero(&s) || ge4(&s, &N) {
            return false;
        }
        let e = e_mod(hash);
        let w = invmod(&s, &N);
        let g = Jac {
            x: GX,
            y: GY,
            z: [1, 0, 0, 0],
        };
        let q = Jac {
            x: qx,
            y: qy,
            z: [1, 0, 0, 0],
        };
        let pt = jadd(
            &jscalar(&mulmod(&e, &w, &N), &g),
            &jscalar(&mulmod(&r, &w, &N), &q),
        );
        match affine(&pt) {
            None => false,
            Some((x1, _)) => {
                let mut x8 = [0u64; 8];
                x8[..4].copy_from_slice(&x1);
                mod_gen(&x8, &N) == r
            }
        }
    }

    /// `ecrecover`: recover the public key (`x‖y`, 64B) from `(sig, recovery_id, hash)`.
    pub fn recover(sig: &[u8; 64], recid: u8, hash: &[u8; 32]) -> Option<[u8; 64]> {
        let r = from_be(&sig[..32]);
        let s = from_be(&sig[32..]);
        if is_zero(&r) || ge4(&r, &N) || is_zero(&s) || ge4(&s, &N) {
            return None;
        }
        // R = (x = r, y with parity recid&1). x = r (assume r < p; recid>=2 would add n, rare)
        let x = r;
        let y2 = fadd(&fmul(&fmul(&x, &x), &x), &[7, 0, 0, 0]); // x³ + 7
        let p1 = {
            let mut e = P;
            let mut c = 1u64;
            for i in 0..4 {
                let t = e[i] as u128 + c as u128;
                e[i] = t as u64;
                c = (t >> 64) as u64;
            }
            e
        }; // p+1
        let y = powmod(&y2, &shr1(&shr1(&p1)), &P); // y = y2^((p+1)/4)  (p ≡ 3 mod 4)
        let y = if (y[0] & 1) as u8 == (recid & 1) {
            y
        } else {
            fsub(&P, &y)
        };
        let rr = Jac {
            x,
            y,
            z: [1, 0, 0, 0],
        };
        let e = e_mod(hash);
        let rinv = invmod(&r, &N);
        // Q = r^-1 (s·R - e·G)
        let sr = jscalar(&s, &rr);
        let eg = jscalar(
            &e,
            &Jac {
                x: GX,
                y: GY,
                z: [1, 0, 0, 0],
            },
        );
        let neg_eg = Jac {
            x: eg.x,
            y: fsub(&P, &eg.y),
            z: eg.z,
        };
        let q = jscalar(&rinv, &jadd(&sr, &neg_eg));
        let (qx, qy) = affine(&q)?;
        let mut o = [0u8; 64];
        o[..32].copy_from_slice(&to_be(&qx));
        o[32..].copy_from_slice(&to_be(&qy));
        Some(o)
    }
}
pub mod x509 {
    //! x509 chain verification — a certificate chain is **frictionless up the chain** (`ThreatModel`):
    //! each cert's signature is verified against its **issuer's** public key, decided at each cell
    //! (`secure_decided_at_one_cell`); a broken/forged link is **friction** and the chain is rejected.
    //! `verify_chain` IS the threat-model fold (`frictionless` ⟺ every link intertwines). The DER parse
    //! is the α (`UniversalEncoding` — the universal decode) that produces the abstract `Cert`; a minimal
    //! TLV walker is here so "parse is a fold, verify is the fold" is concrete. Signatures via our own
    //! `ed25519_verify` / `ecdsa_p256_verify` + `sha256` — zero-dep outside `hashtrinity`.
    use crate::hashtrinity::crypto::{ecdsa_p256_verify, ed25519_verify, sha256};

    // ── Minimal DER TLV walker (the α: DER is one recursive tag-length-value fold) ─────────────────────
    /// One DER element at `off`: returns `(tag, content_start, content_end, next_off)`.
    pub fn der_tlv(d: &[u8], off: usize) -> Option<(u8, usize, usize, usize)> {
        if off >= d.len() {
            return None;
        }
        let tag = d[off];
        let l0 = *d.get(off + 1)?;
        let (len, hdr) = if l0 < 0x80 {
            (l0 as usize, 2)
        } else {
            let nb = (l0 & 0x7f) as usize;
            if nb == 0 || nb > 4 || off + 2 + nb > d.len() {
                return None;
            }
            let mut v = 0usize;
            for i in 0..nb {
                v = (v << 8) | d[off + 2 + i] as usize;
            }
            (v, 2 + nb)
        };
        let cs = off + hdr;
        let ce = cs + len;
        if ce > d.len() {
            return None;
        }
        Some((tag, cs, ce, ce))
    }
    /// Walk the immediate children of the SEQUENCE/SET whose content is `[cs, ce)`.
    pub fn der_children(d: &[u8], cs: usize, ce: usize) -> Vec<(u8, usize, usize)> {
        let mut out = Vec::new();
        let mut o = cs;
        while o < ce {
            match der_tlv(d, o) {
                Some((t, s, e, n)) => {
                    out.push((t, s, e));
                    o = n;
                }
                None => break,
            }
        }
        out
    }

    // ── The abstract certificate (what the DER parse yields; what the fold consumes) ──────────────────
    #[derive(Clone, Copy, PartialEq)]
    pub enum SigAlg {
        Ed25519,
        EcdsaP256,
    }
    #[derive(Clone)]
    pub struct Cert {
        pub issuer: String,
        pub subject: String,
        pub subject_pubkey: Vec<u8>, // SPKI: 32B (ed25519) or 64B (P-256, x‖y)
        pub tbs: Vec<u8>,            // the TBSCertificate bytes (what the signature covers)
        pub sig: Vec<u8>,            // the signature (64B for both here)
        pub alg: SigAlg,
    }

    /// One link's friction check: `cert.sig` over `cert.tbs`, under the **issuer's** key. The one-cell probe.
    fn verify_link(cert: &Cert, issuer_pubkey: &[u8]) -> bool {
        match cert.alg {
            SigAlg::Ed25519 => {
                if issuer_pubkey.len() != 32 || cert.sig.len() != 64 {
                    return false;
                }
                let mut pk = [0u8; 32];
                pk.copy_from_slice(issuer_pubkey);
                let mut s = [0u8; 64];
                s.copy_from_slice(&cert.sig);
                ed25519_verify(&pk, &cert.tbs, &s)
            }
            SigAlg::EcdsaP256 => {
                if issuer_pubkey.len() != 64 || cert.sig.len() != 64 {
                    return false;
                }
                let mut pk = [0u8; 64];
                pk.copy_from_slice(issuer_pubkey);
                let mut s = [0u8; 64];
                s.copy_from_slice(&cert.sig);
                ecdsa_p256_verify(&pk, &sha256(&cert.tbs), &s) // ECDSA signs the hash
            }
        }
    }

    /// **THE CHAIN-FOLD.** `chain = [leaf, …, root]`. Each cert is verified against the next cert's
    /// (issuer's) public key; the root is verified against the `trust_anchor` key, and the issuer↔subject
    /// names must link. Returns true (frictionless) iff **every** link intertwines — a single forged or
    /// broken link is friction and the whole chain is rejected. This is `ThreatModel`: security is the
    /// standing of every cell's equation, up the chain, decided one cell at a time. -/
    pub fn verify_chain(chain: &[Cert], trust_anchor_pubkey: &[u8], trust_anchor_name: &str) -> bool {
        if chain.is_empty() {
            return false;
        }
        for i in 0..chain.len() {
            let (issuer_pk, issuer_name): (&[u8], &str) = if i + 1 < chain.len() {
                (&chain[i + 1].subject_pubkey, chain[i + 1].subject.as_str())
            } else {
                (trust_anchor_pubkey, trust_anchor_name)
            };
            if chain[i].issuer != issuer_name {
                return false;
            } // the name linkage
            if !verify_link(&chain[i], issuer_pk) {
                return false;
            } // friction at this cell → reject
        }
        true
    }

    /// Extract the first URI SubjectAltName (the SPIFFE ID) from an X.509-SVID DER.
    pub fn extract_uri_san(cert: &[u8]) -> Option<String> {
        let needle = [0x06, 0x03, 0x55, 0x1d, 0x11]; // OID 2.5.29.17
        let pos = cert.windows(5).position(|w| w == needle)?;
        let mut o = pos + 5;
        if cert.get(o) == Some(&0x01) {
            o += 3;
        } // skip optional critical BOOLEAN
        let (t, s, _e, _) = der_tlv(cert, o)?;
        if t != 0x04 {
            return None;
        } // extnValue OCTET STRING
        let (t2, s2, e2, _) = der_tlv(cert, s)?;
        if t2 != 0x30 {
            return None;
        } // GeneralNames SEQUENCE
        for (gt, gs, ge) in der_children(cert, s2, e2) {
            if gt == 0x86 {
                return String::from_utf8(cert[gs..ge].to_vec()).ok();
            } // [6] URI
        }
        None
    }

    /// Validate an ed25519 X.509-SVID against a CA public key + a trust domain. Returns the SPIFFE ID iff
    /// the CA signature verifies AND the ID is in `trust_domain`. The full SVID check, on our crypto.
    pub fn verify_x509_svid(cert: &[u8], ca_pk: &[u8; 32], trust_domain: &str) -> Option<String> {
        let (_, cs, _ce, _) = der_tlv(cert, 0)?; // Certificate SEQUENCE
        let (_, _tcs, tce, tnext) = der_tlv(cert, cs)?; // tbsCertificate (first child)
        let tbs = &cert[cs..tce]; // the exact bytes the CA signed
        let (_, _acs, _ace, anext) = der_tlv(cert, tnext)?; // signatureAlgorithm
        let (_, scs, sce, _) = der_tlv(cert, anext)?; // signatureValue BIT STRING
        let sig_bytes = &cert[scs + 1..sce]; // skip the unused-bits byte
        if sig_bytes.len() != 64 {
            return None;
        }
        let mut sig = [0u8; 64];
        sig.copy_from_slice(sig_bytes);
        if !crate::hashtrinity::crypto::ed25519_verify(ca_pk, tbs, &sig) {
            return None;
        } // CA signature
        let id = extract_uri_san(cert)?;
        let td = id.strip_prefix("spiffe://")?.split('/').next()?;
        if td == trust_domain {
            Some(id)
        } else {
            None
        }
    }
}
pub use aes_ctr::aes256_ctr;
pub mod argon2 {
    //! Argon2id (RFC 9106) — the memory-hard password KDF (the modern default; PHC winner). Built on our
    //! BLAKE2b: `H'` variable-length hash, the `G` compression (`GB` permutation), the segment fill with
    //! argon2id's mixed data-independent/dependent indexing. Gated on the RFC 9106 known-answer. Correctly
    //! memory-hard — this is the deliberately-slow form (server-relief in `pwhash` is the position lever).
    #![allow(clippy::needless_range_loop, clippy::too_many_arguments)]
    use crate::hashtrinity::crypto::blake2::blake2b;

    type Block = [u64; 128]; // 1024 bytes

    fn h_prime(input: &[u8], out_len: usize) -> Vec<u8> {
        let mut prefixed = (out_len as u32).to_le_bytes().to_vec();
        prefixed.extend_from_slice(input);
        if out_len <= 64 {
            return blake2b(&prefixed, out_len);
        }
        let r = out_len.div_ceil(32) - 2;
        let mut out = Vec::with_capacity(out_len);
        let mut v = blake2b(&prefixed, 64);
        out.extend_from_slice(&v[..32]);
        for _ in 1..r {
            v = blake2b(&v, 64);
            out.extend_from_slice(&v[..32]);
        }
        v = blake2b(&v, out_len - 32 * r);
        out.extend_from_slice(&v);
        out
    }
    fn bytes_to_block(b: &[u8]) -> Block {
        let mut o = [0u64; 128];
        for i in 0..128 {
            o[i] = u64::from_le_bytes(b[i * 8..i * 8 + 8].try_into().unwrap());
        }
        o
    }
    fn block_to_bytes(b: &Block) -> [u8; 1024] {
        let mut o = [0u8; 1024];
        for i in 0..128 {
            o[i * 8..i * 8 + 8].copy_from_slice(&b[i].to_le_bytes());
        }
        o
    }

    fn gb(v: &mut [u64; 16], a: usize, b: usize, c: usize, d: usize) {
        let t = |x: u64| x & 0xffff_ffff;
        v[a] = v[a]
            .wrapping_add(v[b])
            .wrapping_add(2u64.wrapping_mul(t(v[a])).wrapping_mul(t(v[b])));
        v[d] = (v[d] ^ v[a]).rotate_right(32);
        v[c] = v[c]
            .wrapping_add(v[d])
            .wrapping_add(2u64.wrapping_mul(t(v[c])).wrapping_mul(t(v[d])));
        v[b] = (v[b] ^ v[c]).rotate_right(24);
        v[a] = v[a]
            .wrapping_add(v[b])
            .wrapping_add(2u64.wrapping_mul(t(v[a])).wrapping_mul(t(v[b])));
        v[d] = (v[d] ^ v[a]).rotate_right(16);
        v[c] = v[c]
            .wrapping_add(v[d])
            .wrapping_add(2u64.wrapping_mul(t(v[c])).wrapping_mul(t(v[d])));
        v[b] = (v[b] ^ v[c]).rotate_right(63);
    }
    fn permute(v: &mut [u64; 16]) {
        gb(v, 0, 4, 8, 12);
        gb(v, 1, 5, 9, 13);
        gb(v, 2, 6, 10, 14);
        gb(v, 3, 7, 11, 15);
        gb(v, 0, 5, 10, 15);
        gb(v, 1, 6, 11, 12);
        gb(v, 2, 7, 8, 13);
        gb(v, 3, 4, 9, 14);
    }
    /// G(X, Y) = Z, the argon2 compression (P over rows then columns of R = X⊕Y, then Z = Q⊕R).
    fn g(x: &Block, y: &Block) -> Block {
        let mut r = [0u64; 128];
        for i in 0..128 {
            r[i] = x[i] ^ y[i];
        }
        let mut q = r;
        for row in 0..8 {
            let mut v = [0u64; 16];
            for k in 0..16 {
                v[k] = q[row * 16 + k];
            }
            permute(&mut v);
            for k in 0..16 {
                q[row * 16 + k] = v[k];
            }
        }
        for col in 0..8 {
            let mut v = [0u64; 16];
            for row in 0..8 {
                v[row * 2] = q[row * 16 + col * 2];
                v[row * 2 + 1] = q[row * 16 + col * 2 + 1];
            }
            permute(&mut v);
            for row in 0..8 {
                q[row * 16 + col * 2] = v[row * 2];
                q[row * 16 + col * 2 + 1] = v[row * 2 + 1];
            }
        }
        for i in 0..128 {
            q[i] ^= r[i];
        }
        q
    }

    /// Argon2id (RFC 9106). `m` = memory in KiB, `t` = passes, `p` = lanes, `tag_len` bytes out.
    pub fn argon2id(
        pwd: &[u8],
        salt: &[u8],
        secret: &[u8],
        ad: &[u8],
        m: u32,
        t: u32,
        p: u32,
        tag_len: u32,
    ) -> Vec<u8> {
        // H0
        let mut buf = Vec::new();
        for v in [p, tag_len, m, t, 0x13, 2] {
            buf.extend_from_slice(&v.to_le_bytes());
        }
        for d in [pwd, salt, secret, ad] {
            buf.extend_from_slice(&(d.len() as u32).to_le_bytes());
            buf.extend_from_slice(d);
        }
        let h0 = blake2b(&buf, 64);

        let lanes = p as usize;
        let mprime = (m as usize / (4 * lanes)) * (4 * lanes);
        let q = mprime / lanes; // columns per lane
        let seg = q / 4; // segment length
        let mut b: Vec<Block> = vec![[0u64; 128]; mprime];
        let at = |lane: usize, col: usize| lane * q + col;

        for lane in 0..lanes {
            for col in 0..2 {
                let mut inp = h0.clone();
                inp.extend_from_slice(&(col as u32).to_le_bytes());
                inp.extend_from_slice(&(lane as u32).to_le_bytes());
                b[at(lane, col)] = bytes_to_block(&h_prime(&inp, 1024));
            }
        }

        for pass in 0..t as usize {
            for slice in 0..4usize {
                for lane in 0..lanes {
                    // data-independent address blocks (argon2i) for pass 0, slices 0..1
                    let data_indep = pass == 0 && slice < 2;
                    let mut addr = [0u64; 128];
                    let mut input_block = [0u64; 128];
                    let mut addr_ctr = 0u64;
                    let refresh_addr = |ctr: &mut u64, inp: &mut Block, out: &mut Block| {
                        *ctr += 1;
                        inp[0] = pass as u64;
                        inp[1] = lane as u64;
                        inp[2] = slice as u64;
                        inp[3] = mprime as u64;
                        inp[4] = t as u64;
                        inp[5] = 2;
                        inp[6] = *ctr;
                        *out = g(&[0u64; 128], &g(&[0u64; 128], inp));
                    };
                    let start = if pass == 0 && slice == 0 { 2 } else { 0 };
                    for idx in start..seg {
                        let col = slice * seg + idx;
                        let prev = if col == 0 {
                            at(lane, q - 1)
                        } else {
                            at(lane, col - 1)
                        };
                        // J1, J2
                        let (j1, j2) = if data_indep {
                            if idx % 128 == 0 {
                                refresh_addr(&mut addr_ctr, &mut input_block, &mut addr);
                            }
                            let w = addr[idx % 128];
                            ((w & 0xffff_ffff) as u32, (w >> 32) as u32)
                        } else {
                            let w = b[prev][0];
                            ((w & 0xffff_ffff) as u32, (w >> 32) as u32)
                        };
                        let ref_lane = if pass == 0 && slice == 0 {
                            lane
                        } else {
                            (j2 as usize) % lanes
                        };
                        // reference area size
                        let same = ref_lane == lane;
                        let area: usize = if pass == 0 {
                            if slice == 0 {
                                idx - 1
                            } else if same {
                                slice * seg + idx - 1
                            } else {
                                slice * seg - if idx == 0 { 1 } else { 0 }
                            }
                        } else if same {
                            q - seg + idx - 1
                        } else {
                            q - seg - if idx == 0 { 1 } else { 0 }
                        };
                        // relative position
                        let x = ((j1 as u64) * (j1 as u64)) >> 32;
                        let y = ((area as u64) * x) >> 32;
                        let rel = area as u64 - 1 - y;
                        let start_pos = if pass != 0 && slice != 3 {
                            (slice + 1) * seg
                        } else {
                            0
                        };
                        let ref_col = (start_pos + rel as usize) % q;
                        let newb = g(&b[prev], &b[at(ref_lane, ref_col)]);
                        let cur = at(lane, col);
                        if pass == 0 {
                            b[cur] = newb;
                        } else {
                            for i in 0..128 {
                                b[cur][i] ^= newb[i];
                            }
                        }
                    }
                }
            }
        }

        // final block = XOR of the last column of every lane
        let mut final_b = b[at(0, q - 1)];
        for lane in 1..lanes {
            for i in 0..128 {
                final_b[i] ^= b[at(lane, q - 1)][i];
            }
        }
        h_prime(&block_to_bytes(&final_b), tag_len as usize)
    }

    // ══════════════════════════════════════════════════════════════════════════════════════════════
    // PHC-string masquerade — the `argon2` crate's public surface (`Params`/`ParamsBuilder`/
    // `SaltString`/`PasswordHash`/`Argon2`/`PasswordHasher`/`PasswordVerifier`), reproducing the
    // standard `$argon2id$v=19$m=..,t=..,p=..$<salt>$<hash>` (RFC 9106 §6.2 / the `argon2` crate's own
    // PHC format) over `argon2id` above, so existing stored password hashes stay valid: same
    // algorithm, same params extracted from the string, same salt, same tag — a re-derived hash is
    // byte-identical. Replaces `argon2` (a third-party crate we don't need once our own `argon2id`
    // exists) across the codebase's password-hashing call sites.
    use crate::hashtrinity::base64::{engine::general_purpose::STANDARD_NO_PAD, Engine as _};
    use crate::hashtrinity::crypto::rand_bytes;

    #[derive(Debug)]
    pub enum Error {
        Algorithm,
        Version,
        Params(&'static str),
        B64,
        Crypto,
    }

    impl std::fmt::Display for Error {
        fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
            write!(f, "argon2 error: {self:?}")
        }
    }

    impl std::error::Error for Error {}

    #[derive(Clone, Copy, Debug, PartialEq, Eq)]
    pub enum Algorithm {
        Argon2d,
        Argon2i,
        Argon2id,
    }

    impl Algorithm {
        fn ident(self) -> &'static str {
            match self {
                Algorithm::Argon2d => "argon2d",
                Algorithm::Argon2i => "argon2i",
                Algorithm::Argon2id => "argon2id",
            }
        }

        fn from_ident(s: &str) -> Result<Self, Error> {
            match s {
                "argon2d" => Ok(Algorithm::Argon2d),
                "argon2i" => Ok(Algorithm::Argon2i),
                "argon2id" => Ok(Algorithm::Argon2id),
                _ => Err(Error::Algorithm),
            }
        }
    }

    #[derive(Clone, Copy, Debug, PartialEq, Eq)]
    pub enum Version {
        V0x10,
        V0x13,
    }

    impl Version {
        fn as_u32(self) -> u32 {
            match self {
                Version::V0x10 => 0x10,
                Version::V0x13 => 0x13,
            }
        }

        fn from_u32(v: u32) -> Result<Self, Error> {
            match v {
                0x10 => Ok(Version::V0x10),
                0x13 => Ok(Version::V0x13),
                _ => Err(Error::Version),
            }
        }
    }

    /// `m_cost` (KiB), `t_cost` (passes), `p_cost` (lanes), optional `output_len` (default 32) —
    /// same shape and defaults as the `argon2` crate's own `Params`.
    #[derive(Clone, Copy, Debug, PartialEq, Eq)]
    pub struct Params {
        m_cost: u32,
        t_cost: u32,
        p_cost: u32,
        output_len: Option<usize>,
    }

    impl Params {
        pub fn new(
            m_cost: u32,
            t_cost: u32,
            p_cost: u32,
            output_len: Option<usize>,
        ) -> Result<Self, Error> {
            if m_cost == 0 || t_cost == 0 || p_cost == 0 {
                return Err(Error::Params("m_cost/t_cost/p_cost must be nonzero"));
            }
            Ok(Self {
                m_cost,
                t_cost,
                p_cost,
                output_len,
            })
        }

        pub fn m_cost(&self) -> u32 {
            self.m_cost
        }
        pub fn t_cost(&self) -> u32 {
            self.t_cost
        }
        pub fn p_cost(&self) -> u32 {
            self.p_cost
        }
        pub fn output_len(&self) -> Option<usize> {
            self.output_len
        }
    }

    impl Default for Params {
        /// The `argon2` crate's own `Params::DEFAULT` (RFC 9106 second recommended option).
        fn default() -> Self {
            Self {
                m_cost: 19_456,
                t_cost: 2,
                p_cost: 1,
                output_len: None,
            }
        }
    }

    impl TryFrom<&PasswordHash<'_>> for Params {
        type Error = Error;
        fn try_from(hash: &PasswordHash<'_>) -> Result<Self, Error> {
            Ok(hash.params)
        }
    }

    #[derive(Default)]
    pub struct ParamsBuilder {
        m_cost: Option<u32>,
        t_cost: Option<u32>,
        p_cost: Option<u32>,
        output_len: Option<usize>,
    }

    impl ParamsBuilder {
        pub fn new() -> Self {
            Self::default()
        }
        pub fn m_cost(mut self, v: u32) -> Self {
            self.m_cost = Some(v);
            self
        }
        pub fn t_cost(mut self, v: u32) -> Self {
            self.t_cost = Some(v);
            self
        }
        pub fn p_cost(mut self, v: u32) -> Self {
            self.p_cost = Some(v);
            self
        }
        pub fn output_len(mut self, v: usize) -> Self {
            self.output_len = Some(v);
            self
        }

        pub fn build(self) -> Result<Params, Error> {
            let d = Params::default();
            Params::new(
                self.m_cost.unwrap_or(d.m_cost),
                self.t_cost.unwrap_or(d.t_cost),
                self.p_cost.unwrap_or(d.p_cost),
                self.output_len,
            )
        }
    }

    /// `password_hash::rand_core::OsRng` — the salt CSPRNG source (`SaltString::generate(&mut OsRng)`
    /// matches the real crate's call shape; `rand_bytes` above is what actually reads it).
    pub mod rand_core {
        pub struct OsRng;
    }

    /// A random, PHC-encoded salt string (16 bytes, matching the `argon2`/`password-hash` crate's own
    /// default salt length).
    #[derive(Clone, Debug)]
    pub struct SaltString(String);

    impl SaltString {
        pub fn generate(_rng: &mut rand_core::OsRng) -> Self {
            Self(STANDARD_NO_PAD.encode(rand_bytes(16)))
        }

        pub fn as_str(&self) -> &str {
            &self.0
        }

        fn decode(&self) -> Result<Vec<u8>, Error> {
            STANDARD_NO_PAD.decode(&self.0).map_err(|_| Error::B64)
        }
    }

    impl AsRef<str> for SaltString {
        fn as_ref(&self) -> &str {
            &self.0
        }
    }

    /// A parsed (or freshly-produced) PHC string: `$argon2id$v=19$m=..,t=..,p=..$<salt>$<hash>`.
    /// Owns its salt/hash bytes so it can `Display` back to the exact same string (used both for
    /// freshly-hashed passwords and for re-parsing a stored one during verification).
    #[derive(Clone, Debug)]
    pub struct PasswordHash<'a> {
        algorithm: Algorithm,
        version: Version,
        params: Params,
        salt_b64: std::borrow::Cow<'a, str>,
        hash: Vec<u8>,
    }

    impl<'a> PasswordHash<'a> {
        pub fn new(s: &'a str) -> Result<Self, Error> {
            let rest = s
                .strip_prefix('$')
                .ok_or(Error::Params("missing leading '$'"))?;
            let mut parts = rest.split('$');
            let algorithm = Algorithm::from_ident(parts.next().ok_or(Error::Algorithm)?)?;
            let version_field = parts.next().ok_or(Error::Version)?;
            let version = Version::from_u32(
                version_field
                    .strip_prefix("v=")
                    .ok_or(Error::Version)?
                    .parse::<u32>()
                    .map_err(|_| Error::Version)?,
            )?;
            let params_field = parts.next().ok_or(Error::Params("missing params field"))?;
            let (mut m_cost, mut t_cost, mut p_cost) = (None, None, None);
            for kv in params_field.split(',') {
                let (k, v) = kv.split_once('=').ok_or(Error::Params("malformed param"))?;
                let v: u32 = v.parse().map_err(|_| Error::Params("non-numeric param"))?;
                match k {
                    "m" => m_cost = Some(v),
                    "t" => t_cost = Some(v),
                    "p" => p_cost = Some(v),
                    _ => return Err(Error::Params("unknown param key")),
                }
            }
            let params = Params::new(
                m_cost.ok_or(Error::Params("missing m"))?,
                t_cost.ok_or(Error::Params("missing t"))?,
                p_cost.ok_or(Error::Params("missing p"))?,
                None,
            )?;
            let salt_b64 = parts.next().ok_or(Error::Params("missing salt"))?;
            let hash_b64 = parts.next().ok_or(Error::Params("missing hash"))?;
            let hash = STANDARD_NO_PAD.decode(hash_b64).map_err(|_| Error::B64)?;
            Ok(Self {
                algorithm,
                version,
                params,
                salt_b64: std::borrow::Cow::Borrowed(salt_b64),
                hash,
            })
        }
    }

    impl std::fmt::Display for PasswordHash<'_> {
        fn fmt(&self, f: &mut std::fmt::Formatter<'_>) -> std::fmt::Result {
            write!(
                f,
                "${}$v={}$m={},t={},p={}${}${}",
                self.algorithm.ident(),
                self.version.as_u32(),
                self.params.m_cost,
                self.params.t_cost,
                self.params.p_cost,
                self.salt_b64,
                STANDARD_NO_PAD.encode(&self.hash),
            )
        }
    }

    /// The `argon2` crate's `Argon2` hasher/verifier, backed by [`argon2id`] above.
    pub struct Argon2 {
        algorithm: Algorithm,
        version: Version,
        params: Params,
    }

    impl Argon2 {
        pub fn new(algorithm: Algorithm, version: Version, params: Params) -> Self {
            Self {
                algorithm,
                version,
                params,
            }
        }

        fn derive(&self, password: &[u8], salt: &[u8]) -> Vec<u8> {
            // `argon2id` above is RFC 9106 argon2id-shaped, always — `Algorithm`/`Version` are carried
            // through the PHC string for round-trip fidelity (what gets stored/compared), not routed
            // to a different KDF variant.
            let tag_len = self.params.output_len.unwrap_or(32) as u32;
            argon2id(
                password,
                salt,
                &[],
                &[],
                self.params.m_cost,
                self.params.t_cost,
                self.params.p_cost,
                tag_len,
            )
        }
    }

    impl Default for Argon2 {
        fn default() -> Self {
            Self::new(Algorithm::Argon2id, Version::V0x13, Params::default())
        }
    }

    pub trait PasswordHasher {
        fn hash_password<'a>(
            &self,
            password: &[u8],
            salt: &'a SaltString,
        ) -> Result<PasswordHash<'a>, Error>;
    }

    pub trait PasswordVerifier {
        fn verify_password(&self, password: &[u8], hash: &PasswordHash<'_>) -> Result<(), Error>;
    }

    impl PasswordHasher for Argon2 {
        fn hash_password<'a>(
            &self,
            password: &[u8],
            salt: &'a SaltString,
        ) -> Result<PasswordHash<'a>, Error> {
            let salt_bytes = salt.decode()?;
            let hash = self.derive(password, &salt_bytes);
            Ok(PasswordHash {
                algorithm: self.algorithm,
                version: self.version,
                params: self.params,
                salt_b64: std::borrow::Cow::Borrowed(salt.as_str()),
                hash,
            })
        }
    }

    impl PasswordVerifier for Argon2 {
        fn verify_password(&self, password: &[u8], hash: &PasswordHash<'_>) -> Result<(), Error> {
            let salt_bytes = STANDARD_NO_PAD
                .decode(hash.salt_b64.as_ref())
                .map_err(|_| Error::B64)?;
            let tag_len = hash.params.output_len.unwrap_or(32) as u32;
            let recomputed = argon2id(
                password,
                &salt_bytes,
                &[],
                &[],
                hash.params.m_cost,
                hash.params.t_cost,
                hash.params.p_cost,
                tag_len,
            );
            if crate::hashtrinity::crypto::ct_eq(&recomputed, &hash.hash) {
                Ok(())
            } else {
                Err(Error::Crypto)
            }
        }
    }

    /// `argon2::password_hash` — the sibling module the real crate splits `SaltString`/`rand_core`
    /// into, kept as a re-export so `argon2::password_hash::{SaltString, rand_core::OsRng}` call
    /// sites need no changes beyond the crate name.
    pub mod password_hash {
        pub use super::{rand_core, Error, PasswordHash, SaltString};
    }

    #[cfg(test)]
    mod phc_tests {
        use super::*;

        #[test]
        fn hash_then_verify_round_trips() {
            let params = Params::new(19_456, 2, 1, None).unwrap();
            let argon2 = Argon2::new(Algorithm::Argon2id, Version::V0x13, params);
            let salt = SaltString::generate(&mut rand_core::OsRng);
            let hashed = argon2
                .hash_password(b"correct horse battery staple", &salt)
                .unwrap();
            let phc_string = hashed.to_string();
            assert!(phc_string.starts_with("$argon2id$v=19$m=19456,t=2,p=1$"));

            // re-parse the stored string exactly like `compare_passwords` does
            let parsed = PasswordHash::new(&phc_string).unwrap();
            Argon2::default()
                .verify_password(b"correct horse battery staple", &parsed)
                .unwrap();

            // wrong password must fail
            assert!(Argon2::default()
                .verify_password(b"wrong password", &parsed)
                .is_err());
        }

        #[test]
        fn params_roundtrip_through_stored_hash() {
            let params = Params::new(32768, 3, 2, None).unwrap();
            let argon2 = Argon2::new(Algorithm::Argon2id, Version::V0x13, params);
            let salt = SaltString::generate(&mut rand_core::OsRng);
            let hashed = argon2.hash_password(b"pw", &salt).unwrap();
            let phc_string = hashed.to_string();

            let parsed = PasswordHash::new(&phc_string).unwrap();
            let extracted = Params::try_from(&parsed).unwrap();
            assert_eq!(extracted.m_cost(), 32768);
            assert_eq!(extracted.t_cost(), 3);
            assert_eq!(extracted.p_cost(), 2);
        }

        #[test]
        fn different_salts_produce_different_hashes() {
            let argon2 = Argon2::default();
            let salt1 = SaltString::generate(&mut rand_core::OsRng);
            let salt2 = SaltString::generate(&mut rand_core::OsRng);
            let h1 = argon2
                .hash_password(b"same password", &salt1)
                .unwrap()
                .to_string();
            let h2 = argon2
                .hash_password(b"same password", &salt2)
                .unwrap()
                .to_string();
            assert_ne!(h1, h2);
        }
    }
}
pub mod chacha_poly {
    //! ChaCha20-Poly1305 (RFC 8439) — the framework-native AEAD. ChaCha20 is the ARX keystream fold;
    //! **Poly1305 is the B/U accumulator** (`HashTrinity.fuse` in information form: `h = (h+block)·r mod
    //! 2¹³⁰−5`, the Horner fold), and its tag check is `integrity_decided_at_the_cell` — the same object
    //! as SangSec's one-time MAC. Encrypt-then-MAC; decrypt verifies before returning. Gated on RFC 8439.
    #![allow(clippy::needless_range_loop)]

    // ── ChaCha20 (RFC 8439 §2.3): the ARX quarter-round fold ───────────────────────────────────────────
    fn qr(s: &mut [u32; 16], a: usize, b: usize, c: usize, d: usize) {
        s[a] = s[a].wrapping_add(s[b]);
        s[d] ^= s[a];
        s[d] = s[d].rotate_left(16);
        s[c] = s[c].wrapping_add(s[d]);
        s[b] ^= s[c];
        s[b] = s[b].rotate_left(12);
        s[a] = s[a].wrapping_add(s[b]);
        s[d] ^= s[a];
        s[d] = s[d].rotate_left(8);
        s[c] = s[c].wrapping_add(s[d]);
        s[b] ^= s[c];
        s[b] = s[b].rotate_left(7);
    }
    fn chacha_block(key: &[u8; 32], counter: u32, nonce: &[u8; 12]) -> [u8; 64] {
        let mut s = [0u32; 16];
        s[0] = 0x61707865;
        s[1] = 0x3320646e;
        s[2] = 0x79622d32;
        s[3] = 0x6b206574;
        for i in 0..8 {
            s[4 + i] = u32::from_le_bytes(key[4 * i..4 * i + 4].try_into().unwrap());
        }
        s[12] = counter;
        for i in 0..3 {
            s[13 + i] = u32::from_le_bytes(nonce[4 * i..4 * i + 4].try_into().unwrap());
        }
        let init = s;
        for _ in 0..10 {
            qr(&mut s, 0, 4, 8, 12);
            qr(&mut s, 1, 5, 9, 13);
            qr(&mut s, 2, 6, 10, 14);
            qr(&mut s, 3, 7, 11, 15);
            qr(&mut s, 0, 5, 10, 15);
            qr(&mut s, 1, 6, 11, 12);
            qr(&mut s, 2, 7, 8, 13);
            qr(&mut s, 3, 4, 9, 14);
        }
        let mut out = [0u8; 64];
        for i in 0..16 {
            out[4 * i..4 * i + 4].copy_from_slice(&s[i].wrapping_add(init[i]).to_le_bytes());
        }
        out
    }
    fn chacha20(key: &[u8; 32], counter: u32, nonce: &[u8; 12], data: &[u8]) -> Vec<u8> {
        let mut out = Vec::with_capacity(data.len());
        for (blk, chunk) in data.chunks(64).enumerate() {
            let ks = chacha_block(key, counter + blk as u32, nonce);
            for (i, &b) in chunk.iter().enumerate() {
                out.push(b ^ ks[i]);
            }
        }
        out
    }

    // ── Poly1305 (RFC 8439 §2.5): the B/U ACCUMULATOR — `h = (h+block)·r mod 2¹³⁰−5`, Horner ────────────
    fn poly1305(key: &[u8; 32], m: &[u8]) -> [u8; 16] {
        let ld = |b: &[u8]| u32::from_le_bytes([b[0], b[1], b[2], b[3]]);
        let (t0, t1, t2, t3) = (ld(&key[0..]), ld(&key[4..]), ld(&key[8..]), ld(&key[12..]));
        // r, clamped, in 5×26-bit limbs
        let r0 = (t0) & 0x3ffffff;
        let r1 = ((t0 >> 26) | (t1 << 6)) & 0x3ffff03;
        let r2 = ((t1 >> 20) | (t2 << 12)) & 0x3ffc0ff;
        let r3 = ((t2 >> 14) | (t3 << 18)) & 0x3f03fff;
        let r4 = (t3 >> 8) & 0x00fffff;
        let (s1, s2, s3, s4) = (r1 * 5, r2 * 5, r3 * 5, r4 * 5);
        let (mut h0, mut h1, mut h2, mut h3, mut h4) = (0u32, 0u32, 0u32, 0u32, 0u32);
        let mut i = 0;
        while i < m.len() {
            let n = (m.len() - i).min(16);
            let mut blk = [0u8; 17];
            blk[..n].copy_from_slice(&m[i..i + n]);
            blk[n] = 1; // the terminating 1 bit (full block ⇒ bit 2¹²⁸; partial ⇒ after byte n)
            let (b0, b1, b2, b3) = (ld(&blk[0..]), ld(&blk[4..]), ld(&blk[8..]), ld(&blk[12..]));
            h0 += b0 & 0x3ffffff;
            h1 += ((b0 >> 26) | (b1 << 6)) & 0x3ffffff;
            h2 += ((b1 >> 20) | (b2 << 12)) & 0x3ffffff;
            h3 += ((b2 >> 14) | (b3 << 18)) & 0x3ffffff;
            h4 += (b3 >> 8) | ((blk[16] as u32) << 24);
            // h = (h * r) mod 2¹³⁰−5 — the accumulator merge
            let d0 = h0 as u64 * r0 as u64
                + h1 as u64 * s4 as u64
                + h2 as u64 * s3 as u64
                + h3 as u64 * s2 as u64
                + h4 as u64 * s1 as u64;
            let d1 = h0 as u64 * r1 as u64
                + h1 as u64 * r0 as u64
                + h2 as u64 * s4 as u64
                + h3 as u64 * s3 as u64
                + h4 as u64 * s2 as u64;
            let d2 = h0 as u64 * r2 as u64
                + h1 as u64 * r1 as u64
                + h2 as u64 * r0 as u64
                + h3 as u64 * s4 as u64
                + h4 as u64 * s3 as u64;
            let d3 = h0 as u64 * r3 as u64
                + h1 as u64 * r2 as u64
                + h2 as u64 * r1 as u64
                + h3 as u64 * r0 as u64
                + h4 as u64 * s4 as u64;
            let d4 = h0 as u64 * r4 as u64
                + h1 as u64 * r3 as u64
                + h2 as u64 * r2 as u64
                + h3 as u64 * r1 as u64
                + h4 as u64 * r0 as u64;
            let mut c = d0 >> 26;
            h0 = (d0 as u32) & 0x3ffffff;
            let d1 = d1 + c;
            c = d1 >> 26;
            h1 = (d1 as u32) & 0x3ffffff;
            let d2 = d2 + c;
            c = d2 >> 26;
            h2 = (d2 as u32) & 0x3ffffff;
            let d3 = d3 + c;
            c = d3 >> 26;
            h3 = (d3 as u32) & 0x3ffffff;
            let d4 = d4 + c;
            c = d4 >> 26;
            h4 = (d4 as u32) & 0x3ffffff;
            h0 += (c as u32) * 5;
            c = (h0 >> 26) as u64;
            h0 &= 0x3ffffff;
            h1 += c as u32;
            i += n;
        }
        // final carry
        let mut c = h1 >> 26;
        h1 &= 0x3ffffff;
        h2 += c;
        c = h2 >> 26;
        h2 &= 0x3ffffff;
        h3 += c;
        c = h3 >> 26;
        h3 &= 0x3ffffff;
        h4 += c;
        c = h4 >> 26;
        h4 &= 0x3ffffff;
        h0 += c * 5;
        c = h0 >> 26;
        h0 &= 0x3ffffff;
        h1 += c;
        // compute h - p (p = 2¹³⁰-5): g = h + 5, if g ≥ 2¹³⁰ then h = g mod 2¹³⁰
        let mut g0 = h0.wrapping_add(5);
        c = g0 >> 26;
        g0 &= 0x3ffffff;
        let mut g1 = h1 + c;
        c = g1 >> 26;
        g1 &= 0x3ffffff;
        let mut g2 = h2 + c;
        c = g2 >> 26;
        g2 &= 0x3ffffff;
        let mut g3 = h3 + c;
        c = g3 >> 26;
        g3 &= 0x3ffffff;
        let g4 = h4.wrapping_add(c).wrapping_sub(1 << 26);
        let mask = (g4 >> 31).wrapping_sub(1); // if g4 didn't borrow, use g
        let nmask = !mask;
        h0 = (h0 & nmask) | (g0 & mask);
        h1 = (h1 & nmask) | (g1 & mask);
        h2 = (h2 & nmask) | (g2 & mask);
        h3 = (h3 & nmask) | (g3 & mask);
        h4 = (h4 & nmask) | (g4 & mask);
        // serialize h (mod 2¹²⁸) + s
        let f0 = (h0 | (h1 << 26)) as u64;
        let f1 = ((h1 >> 6) | (h2 << 20)) as u64;
        let f2 = ((h2 >> 12) | (h3 << 14)) as u64;
        let f3 = ((h3 >> 18) | (h4 << 8)) as u64;
        let s0 = u32::from_le_bytes(key[16..20].try_into().unwrap()) as u64;
        let s1v = u32::from_le_bytes(key[20..24].try_into().unwrap()) as u64;
        let s2v = u32::from_le_bytes(key[24..28].try_into().unwrap()) as u64;
        let s3v = u32::from_le_bytes(key[28..32].try_into().unwrap()) as u64;
        let mut t = [0u32; 4];
        let mut acc = f0 + s0;
        t[0] = acc as u32;
        acc >>= 32;
        acc += f1 + s1v;
        t[1] = acc as u32;
        acc >>= 32;
        acc += f2 + s2v;
        t[2] = acc as u32;
        acc >>= 32;
        acc += f3 + s3v;
        t[3] = acc as u32;
        let mut tag = [0u8; 16];
        for i in 0..4 {
            tag[4 * i..4 * i + 4].copy_from_slice(&t[i].to_le_bytes());
        }
        tag
    }

    fn poly_key(key: &[u8; 32], nonce: &[u8; 12]) -> [u8; 32] {
        let b = chacha_block(key, 0, nonce);
        let mut k = [0u8; 32];
        k.copy_from_slice(&b[..32]);
        k
    }
    fn aead_mac(otk: &[u8; 32], aad: &[u8], ct: &[u8]) -> [u8; 16] {
        let mut m = Vec::new();
        m.extend_from_slice(aad);
        while m.len() % 16 != 0 {
            m.push(0);
        }
        m.extend_from_slice(ct);
        while m.len() % 16 != 0 {
            m.push(0);
        }
        m.extend_from_slice(&(aad.len() as u64).to_le_bytes());
        m.extend_from_slice(&(ct.len() as u64).to_le_bytes());
        poly1305(otk, &m)
    }
    /// ChaCha20-Poly1305 encrypt → `(ciphertext, 16-byte tag)`.
    pub fn chacha20poly1305_encrypt(
        key: &[u8; 32],
        nonce: &[u8; 12],
        pt: &[u8],
        aad: &[u8],
    ) -> (Vec<u8>, [u8; 16]) {
        let ct = chacha20(key, 1, nonce, pt);
        let tag = aead_mac(&poly_key(key, nonce), aad, &ct);
        (ct, tag)
    }
    /// ChaCha20-Poly1305 decrypt — verifies the tag first (None on tamper).
    pub fn chacha20poly1305_decrypt(
        key: &[u8; 32],
        nonce: &[u8; 12],
        ct: &[u8],
        tag: &[u8; 16],
        aad: &[u8],
    ) -> Option<Vec<u8>> {
        let expect = aead_mac(&poly_key(key, nonce), aad, ct);
        let mut d = 0u8;
        for i in 0..16 {
            d |= expect[i] ^ tag[i];
        }
        if d != 0 {
            return None;
        }
        Some(chacha20(key, 1, nonce, ct))
    }

    /// The bare ChaCha20 block (RFC 8439 §2.3) — one keystream sample at a coordinate (`Table.get` on the
    /// keystream). QUIC header protection reads exactly this: no AEAD, no Poly1305, just the block.
    pub fn chacha20_block(key: &[u8; 32], counter: u32, nonce: &[u8; 12]) -> [u8; 64] {
        chacha_block(key, counter, nonce)
    }
}
pub mod p384 {
    //! ECDSA / NIST P-384 (FIPS 186-4) — the same group-merge as P-256, one field wider (`[u64;6]`, the
    //! `a=-3` Jacobian unchanged). Verify is the one-cell friction check. Gated on RFC 6979's P-384/SHA-384
    //! vector. Zero-dep outside `hashtrinity`. (Structure mirrors `ecdsa.rs`; only the width + constants change.)
    #![allow(clippy::needless_range_loop)]

    type U = [u64; 6]; // 384-bit, little-endian limbs

    // P-384 domain (FIPS 186-4 / SEC 2) → LE limbs.
    const P: U = [
        0x00000000ffffffff,
        0xffffffff00000000,
        0xfffffffffffffffe,
        0xffffffffffffffff,
        0xffffffffffffffff,
        0xffffffffffffffff,
    ];
    const N: U = [
        0xecec196accc52973,
        0x581a0db248b0a77a,
        0xc7634d81f4372ddf,
        0xffffffffffffffff,
        0xffffffffffffffff,
        0xffffffffffffffff,
    ];
    const GX: U = [
        0x3a545e3872760ab7,
        0x5502f25dbf55296c,
        0x59f741e082542a38,
        0x6e1d3b628ba79b98,
        0x8eb1c71ef320ad74,
        0xaa87ca22be8b0537,
    ];
    const GY: U = [
        0x7a431d7c90ea0e5f,
        0x0a60b1ce1d7e819d,
        0xe9da3113b5f0b8c0,
        0xf8f41dbd289a147c,
        0x5d9e98bf9292dc29,
        0x3617de4a96262c6f,
    ];

    fn from_be(b: &[u8]) -> U {
        let mut r = [0u64; 6];
        for i in 0..6 {
            r[i] = u64::from_be_bytes(b[40 - i * 8..48 - i * 8].try_into().unwrap());
        }
        r
    }
    fn is_zero(a: &U) -> bool {
        a == &[0u64; 6]
    }
    fn ge7(a: &[u64; 7], m: &[u64; 7]) -> bool {
        for i in (0..7).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }
    fn sub7(a: &mut [u64; 7], m: &[u64; 7]) {
        let mut br = 0i128;
        for i in 0..7 {
            let v = a[i] as i128 - m[i] as i128 - br;
            if v < 0 {
                a[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                a[i] = v as u64;
                br = 0;
            }
        }
    }
    fn ge6(a: &U, m: &U) -> bool {
        for i in (0..6).rev() {
            if a[i] != m[i] {
                return a[i] > m[i];
            }
        }
        true
    }

    fn mul(a: &U, b: &U) -> [u64; 12] {
        let mut p = [0u64; 12];
        for i in 0..6 {
            let mut cr = 0u128;
            for j in 0..6 {
                let t = a[i] as u128 * b[j] as u128 + p[i + j] as u128 + cr;
                p[i + j] = t as u64;
                cr = t >> 64;
            }
            let mut k = i + 6;
            while cr != 0 && k < 12 {
                let t = p[k] as u128 + cr;
                p[k] = t as u64;
                cr = t >> 64;
                k += 1;
            }
        }
        p
    }
    fn mod_gen(x: &[u64; 12], m: &U) -> U {
        let m7 = [m[0], m[1], m[2], m[3], m[4], m[5], 0];
        let mut rem = [0u64; 7];
        for i in (0..768).rev() {
            let bit = (x[i / 64] >> (i % 64)) & 1;
            let mut c = bit;
            for l in rem.iter_mut() {
                let nc = *l >> 63;
                *l = (*l << 1) | c;
                c = nc;
            }
            if ge7(&rem, &m7) {
                sub7(&mut rem, &m7);
            }
        }
        [rem[0], rem[1], rem[2], rem[3], rem[4], rem[5]]
    }
    fn mulmod(a: &U, b: &U, m: &U) -> U {
        mod_gen(&mul(a, b), m)
    }
    fn addmod(a: &U, b: &U, m: &U) -> U {
        let mut s = [0u64; 7];
        let mut c = 0u128;
        for i in 0..6 {
            let t = a[i] as u128 + b[i] as u128 + c;
            s[i] = t as u64;
            c = t >> 64;
        }
        s[6] = c as u64;
        let m7 = [m[0], m[1], m[2], m[3], m[4], m[5], 0];
        if ge7(&s, &m7) {
            sub7(&mut s, &m7);
        }
        [s[0], s[1], s[2], s[3], s[4], s[5]]
    }
    fn submod(a: &U, b: &U, m: &U) -> U {
        if ge6(a, b) {
            let mut r = *a;
            let mut br = 0i128;
            for i in 0..6 {
                let v = r[i] as i128 - b[i] as i128 - br;
                if v < 0 {
                    r[i] = (v + (1i128 << 64)) as u64;
                    br = 1;
                } else {
                    r[i] = v as u64;
                    br = 0;
                }
            }
            r
        } else {
            addmod(a, &submod(m, b, m), m)
        }
    }
    fn sub_small(a: &U, k: u64) -> U {
        let mut r = *a;
        let mut br = k as i128;
        for i in 0..6 {
            let v = r[i] as i128 - br;
            if v < 0 {
                r[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                r[i] = v as u64;
                br = 0;
            }
        }
        r
    }
    fn powmod(a: &U, e: &U, m: &U) -> U {
        let mut r = [1u64, 0, 0, 0, 0, 0];
        let mut base = *a;
        for i in 0..384 {
            if (e[i / 64] >> (i % 64)) & 1 == 1 {
                r = mulmod(&r, &base, m);
            }
            base = mulmod(&base, &base, m);
        }
        r
    }
    fn invmod(a: &U, m: &U) -> U {
        powmod(a, &sub_small(m, 2), m)
    }

    #[derive(Clone, Copy)]
    struct Jac {
        x: U,
        y: U,
        z: U,
    }
    fn jinf() -> Jac {
        Jac {
            x: [1, 0, 0, 0, 0, 0],
            y: [1, 0, 0, 0, 0, 0],
            z: [0; 6],
        }
    }
    fn fmul(a: &U, b: &U) -> U {
        mulmod(a, b, &P)
    }
    fn fsq(a: &U) -> U {
        mulmod(a, a, &P)
    }
    fn fadd(a: &U, b: &U) -> U {
        addmod(a, b, &P)
    }
    fn fsub(a: &U, b: &U) -> U {
        submod(a, b, &P)
    }

    fn jdouble(p: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *p;
        }
        let delta = fsq(&p.z);
        let gamma = fsq(&p.y);
        let beta = fmul(&p.x, &gamma);
        let t = fmul(&fsub(&p.x, &delta), &fadd(&p.x, &delta));
        let alpha = fadd(&fadd(&t, &t), &t);
        let x3 = fsub(&fsq(&alpha), &{
            let b2 = fadd(&beta, &beta);
            let b4 = fadd(&b2, &b2);
            fadd(&b4, &b4)
        });
        let z3 = fsub(&fsub(&fsq(&fadd(&p.y, &p.z)), &gamma), &delta);
        let g2 = fsq(&gamma);
        let g8 = {
            let a = fadd(&g2, &g2);
            let b = fadd(&a, &a);
            fadd(&b, &b)
        };
        let b4 = {
            let a = fadd(&beta, &beta);
            fadd(&a, &a)
        };
        let y3 = fsub(&fmul(&alpha, &fsub(&b4, &x3)), &g8);
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jadd(p: &Jac, q: &Jac) -> Jac {
        if is_zero(&p.z) {
            return *q;
        }
        if is_zero(&q.z) {
            return *p;
        }
        let z1z1 = fsq(&p.z);
        let z2z2 = fsq(&q.z);
        let u1 = fmul(&p.x, &z2z2);
        let u2 = fmul(&q.x, &z1z1);
        let s1 = fmul(&fmul(&p.y, &q.z), &z2z2);
        let s2 = fmul(&fmul(&q.y, &p.z), &z1z1);
        if u1 == u2 {
            if s1 == s2 {
                return jdouble(p);
            } else {
                return jinf();
            }
        }
        let h = fsub(&u2, &u1);
        let i = fsq(&fadd(&h, &h));
        let j = fmul(&h, &i);
        let rr = fadd(&fsub(&s2, &s1), &fsub(&s2, &s1));
        let v = fmul(&u1, &i);
        let x3 = fsub(&fsub(&fsq(&rr), &j), &fadd(&v, &v));
        let y3 = fsub(&fmul(&rr, &fsub(&v, &x3)), &fmul(&fadd(&s1, &s1), &j));
        let z3 = fmul(&fsub(&fsub(&fsq(&fadd(&p.z, &q.z)), &z1z1), &z2z2), &h);
        Jac {
            x: x3,
            y: y3,
            z: z3,
        }
    }
    fn jscalar(k: &U, p: &Jac) -> Jac {
        let mut r = jinf();
        for i in (0..384).rev() {
            r = jdouble(&r);
            if (k[i / 64] >> (i % 64)) & 1 == 1 {
                r = jadd(&r, p);
            }
        }
        r
    }
    fn affine_x(p: &Jac) -> Option<U> {
        if is_zero(&p.z) {
            return None;
        }
        let zi = invmod(&p.z, &P);
        Some(fmul(&p.x, &fsq(&zi)))
    }

    /// Verify an ECDSA/P-384 signature: `pubkey` = `Qx‖Qy` (96B), `hash` = SHA-384 digest (48B), `sig` =
    /// `r‖s` (96B). Returns true iff valid — the one-cell friction check at the wider curve.
    pub fn ecdsa_p384_verify(pubkey: &[u8; 96], hash: &[u8; 48], sig: &[u8; 96]) -> bool {
        let qx = from_be(&pubkey[..48]);
        let qy = from_be(&pubkey[48..]);
        let r = from_be(&sig[..48]);
        let s = from_be(&sig[48..]);
        if is_zero(&r) || ge6(&r, &N) || is_zero(&s) || ge6(&s, &N) {
            return false;
        }
        let e = from_be(hash);
        let w = invmod(&s, &N);
        let u1 = mulmod(&e, &w, &N);
        let u2 = mulmod(&r, &w, &N);
        let g = Jac {
            x: GX,
            y: GY,
            z: [1, 0, 0, 0, 0, 0],
        };
        let q = Jac {
            x: qx,
            y: qy,
            z: [1, 0, 0, 0, 0, 0],
        };
        let pt = jadd(&jscalar(&u1, &g), &jscalar(&u2, &q));
        match affine_x(&pt) {
            None => false,
            Some(x1) => {
                let mut xr = [0u64; 12];
                xr[..6].copy_from_slice(&x1);
                mod_gen(&xr, &N) == r
            }
        }
    }

    fn to_be48(u: &U) -> [u8; 48] {
        let mut b = [0u8; 48];
        for i in 0..6 {
            b[40 - i * 8..48 - i * 8].copy_from_slice(&u[i].to_be_bytes());
        }
        b
    }
    fn hmac384(k: &[u8], d: &[u8]) -> [u8; 48] {
        crate::hashtrinity::crypto::hmac_sha384(k, d)
    }
    /// RFC 6979 deterministic nonce for P-384/SHA-384 (HMAC-SHA384 DRBG).
    fn rfc6979_k(xo: &[u8; 48], ho: &[u8; 48]) -> U {
        let mut v = [1u8; 48];
        let mut k = [0u8; 48];
        let seed = |flag: u8, k: &[u8; 48], v: &[u8; 48]| {
            let mut b = v.to_vec();
            b.push(flag);
            b.extend_from_slice(xo);
            b.extend_from_slice(ho);
            hmac384(k, &b)
        };
        k = seed(0, &k, &v);
        v = hmac384(&k, &v);
        k = seed(1, &k, &v);
        v = hmac384(&k, &v);
        loop {
            v = hmac384(&k, &v);
            let c = from_be(&v);
            if !is_zero(&c) && !ge6(&c, &N) {
                return c;
            }
            let mut b = v.to_vec();
            b.push(0);
            k = hmac384(&k, &b);
            v = hmac384(&k, &v);
        }
    }
    /// ECDSA/P-384 sign (RFC 6979 deterministic). Returns `r‖s` (96B).
    pub fn ecdsa_p384_sign(private_key: &[u8; 48], hash: &[u8; 48]) -> [u8; 96] {
        let d = from_be(private_key);
        let mut he = [0u64; 12];
        he[..6].copy_from_slice(&from_be(hash));
        let e = mod_gen(&he, &N);
        let k = rfc6979_k(private_key, &to_be48(&e));
        let g = Jac {
            x: GX,
            y: GY,
            z: [1, 0, 0, 0, 0, 0],
        };
        let mut rx = [0u64; 12];
        rx[..6].copy_from_slice(&affine_x(&jscalar(&k, &g)).unwrap());
        let r = mod_gen(&rx, &N);
        let s = mulmod(&invmod(&k, &N), &addmod(&e, &mulmod(&r, &d, &N), &N), &N);
        let mut sig = [0u8; 96];
        sig[..48].copy_from_slice(&to_be48(&r));
        sig[48..].copy_from_slice(&to_be48(&s));
        sig
    }
}
pub mod pwhash {
    //! Password hashing, the framework way — **security and honest-party latency are separable axes**, and
    //! the streaming law separates them by POSITION. The memory-hard fold stays correctly slow (its
    //! sequential, data-dependent fill IS the security — it must NEVER be parallelized into an order-free
    //! merge, or a GPU attacker parallelizes it and the memory-hardness is gone), but it runs at the CLIENT
    //! coordinate, once per login; the SERVER hot path is an O(1) verify (the HashTrinity keep/get face).
    //! `x = B/U` positioned: the drag `U` (the fold) at the edge, the boundary `B` (the O(1) verify) at the
    //! center. An attacker who steals the DB STILL pays the full fold per guess — brute-force resistance
    //! kept, server fast. (The fold below is the argon2-family SHAPE, not RFC 9106 byte-exact; argon2id is
    //! the drop-in for it — the architecture is the point.)
    use crate::hashtrinity::crypto::{ct_eq, sha256};

    /// A memory-hard KDF core: a sequential fill + **data-dependent addressing** over a working buffer —
    /// the property that defeats GPU/ASIC parallelism (an attacker cannot skip the memory or run it wide).
    pub fn memory_hard(password: &[u8], salt: &[u8], mem_blocks: usize, passes: usize) -> [u8; 32] {
        let mut mem = vec![[0u8; 32]; mem_blocks];
        let mut seed = Vec::from(password);
        seed.extend_from_slice(salt);
        mem[0] = sha256(&seed);
        for i in 1..mem_blocks {
            mem[i] = sha256(&mem[i - 1]);
        } // sequential fill
        for _ in 0..passes {
            for i in 0..mem_blocks {
                let prev = mem[(i + mem_blocks - 1) % mem_blocks];
                let j =
                    (u32::from_le_bytes([prev[0], prev[1], prev[2], prev[3]]) as usize) % mem_blocks; // data-dependent index
                let mut buf = [0u8; 64];
                buf[..32].copy_from_slice(&prev);
                buf[32..].copy_from_slice(&mem[j]);
                mem[i] = sha256(&buf);
            }
        }
        let mut all = Vec::with_capacity(mem_blocks * 32);
        for b in &mem {
            all.extend_from_slice(b);
        }
        sha256(&all)
    }
    /// CLIENT (the edge coordinate): the expensive memory-hard fold. This is exactly the attacker's
    /// per-guess cost — brute-force resistance lives here, unchanged.
    pub fn client_derive(password: &[u8], salt: &[u8], mem_blocks: usize, passes: usize) -> [u8; 32] {
        memory_hard(password, salt, mem_blocks, passes)
    }
    /// SERVER register: store a fast hash of the client's fold output (never the password). O(1).
    pub fn server_store(client_h: &[u8; 32]) -> [u8; 32] {
        sha256(client_h)
    }
    /// SERVER verify: O(1) — the HashTrinity keep/get face. The hot path bears NONE of the fold's cost.
    pub fn server_verify(client_h: &[u8; 32], stored: &[u8; 32]) -> bool {
        ct_eq(&sha256(client_h), stored)
    }
}
pub mod quic {
    //! QUIC packet crypto (RFC 9001) — and the corpus-derived *faster* form. The per-packet cipher is
    //! interop-fixed (ChaCha20-Poly1305 packet AEAD + a ChaCha20-block header-protection mask), but the
    //! **schedule** is not: each QUIC packet is a self-contained node (nonce = iv⊕pn, no cross-packet
    //! state), so the packet stream is `Web.node_independent` / `Federation`'s order-free merge — the same
    //! shape as BLAKE3's tree leaves in Song. That independence is a *theorem*, and it licenses processing
    //! packets in ANY order, in parallel. So `quic_seal_batch` fans the independent packets across cores
    //! (the Web `pmapAt` sweep) — bit-identical to sequential, faster by the order-free structure.
    use crate::hashtrinity::crypto::chacha_poly::{
        chacha20_block, chacha20poly1305_decrypt, chacha20poly1305_encrypt,
    };

    /// The QUIC nonce: `iv` XOR the packet number (big-endian, right-aligned in the low 8 bytes). RFC 9001 §5.3.
    fn packet_nonce(iv: &[u8; 12], pn: u64) -> [u8; 12] {
        let mut n = *iv;
        let pnb = pn.to_be_bytes();
        for i in 0..8 {
            n[4 + i] ^= pnb[i];
        }
        n
    }

    /// **Header-protection mask** — one ChaCha20 block sample (RFC 9001 §5.4.4): counter = `sample[0..4]`
    /// (LE), nonce = `sample[4..16]`, mask = the first 5 keystream bytes. The `Table.get` on the keystream:
    /// no AEAD, no Poly1305 — just the block read at the sampled coordinate.
    pub fn quic_hp_mask(hp_key: &[u8; 32], sample: &[u8; 16]) -> [u8; 5] {
        let counter = u32::from_le_bytes([sample[0], sample[1], sample[2], sample[3]]);
        let mut nonce = [0u8; 12];
        nonce.copy_from_slice(&sample[4..16]);
        let b = chacha20_block(hp_key, counter, &nonce);
        [b[0], b[1], b[2], b[3], b[4]]
    }

    /// Seal one packet: payload → ciphertext‖tag, with `header` as AAD. The one node's work.
    pub fn quic_seal(key: &[u8; 32], iv: &[u8; 12], pn: u64, header: &[u8], payload: &[u8]) -> Vec<u8> {
        let nonce = packet_nonce(iv, pn);
        let (mut ct, tag) = chacha20poly1305_encrypt(key, &nonce, payload, header);
        ct.extend_from_slice(&tag);
        ct
    }
    /// Open one packet — `None` on tag failure (integrity at the cell).
    pub fn quic_open(
        key: &[u8; 32],
        iv: &[u8; 12],
        pn: u64,
        header: &[u8],
        sealed: &[u8],
    ) -> Option<Vec<u8>> {
        if sealed.len() < 16 {
            return None;
        }
        let n = sealed.len() - 16;
        let mut tag = [0u8; 16];
        tag.copy_from_slice(&sealed[n..]);
        chacha20poly1305_decrypt(key, &packet_nonce(iv, pn), &sealed[..n], &tag, header)
    }

    /// **THE CORPUS-DERIVED FASTER FORM.** Seal a batch of independent packets in parallel — the Web
    /// `pmapAt` over sovereign nodes, licensed by `Federation`'s order-free merge (packets share no state).
    /// Bit-identical to sealing them sequentially; faster by the parallel schedule the independence proves.
    pub fn quic_seal_batch(
        key: &[u8; 32],
        iv: &[u8; 12],
        packets: &[(u64, Vec<u8>, Vec<u8>)],
    ) -> Vec<Vec<u8>> {
        let cores = std::thread::available_parallelism()
            .map(|x| x.get())
            .unwrap_or(1);
        if cores <= 1 || packets.len() < cores * 2 {
            return packets
                .iter()
                .map(|(pn, h, p)| quic_seal(key, iv, *pn, h, p))
                .collect();
        }
        let chunk = packets.len().div_ceil(cores);
        let mut out: Vec<Vec<u8>> = Vec::with_capacity(packets.len());
        std::thread::scope(|s| {
            let handles: Vec<_> = packets
                .chunks(chunk)
                .map(|ch| {
                    s.spawn(move || {
                        ch.iter()
                            .map(|(pn, h, p)| quic_seal(key, iv, *pn, h, p))
                            .collect::<Vec<_>>()
                    })
                })
                .collect();
            for h in handles {
                out.extend(h.join().unwrap());
            }
        });
        out
    }

    /// AES header-protection mask (RFC 9001 §5.4.3): AES-ECB of the 16-byte sample, first 5 bytes.
    pub fn quic_hp_mask_aes128(hp_key: &[u8; 16], sample: &[u8; 16]) -> [u8; 5] {
        let b = crate::hashtrinity::crypto::aes_gcm::aes128_ecb_block(hp_key, sample);
        [b[0], b[1], b[2], b[3], b[4]]
    }
    pub fn quic_hp_mask_aes256(hp_key: &[u8; 32], sample: &[u8; 16]) -> [u8; 5] {
        let b = crate::hashtrinity::crypto::aes_gcm::aes256_ecb_block(hp_key, sample);
        [b[0], b[1], b[2], b[3], b[4]]
    }

    /// HKDF-Expand-Label (RFC 8446 §7.1) — TLS 1.3 / QUIC labeled expand, over our HMAC-SHA256 fold.
    pub fn hkdf_expand_label(secret: &[u8], label: &str, context: &[u8], len: usize) -> Vec<u8> {
        let full = format!("tls13 {label}");
        let mut info = Vec::new();
        info.extend_from_slice(&(len as u16).to_be_bytes());
        info.push(full.len() as u8);
        info.extend_from_slice(full.as_bytes());
        info.push(context.len() as u8);
        info.extend_from_slice(context);
        let (mut out, mut t, mut i) = (Vec::new(), Vec::<u8>::new(), 1u8);
        while out.len() < len {
            let mut m = t.clone();
            m.extend_from_slice(&info);
            m.push(i);
            t = crate::hashtrinity::crypto::hmac_sha256(secret, &m).to_vec();
            out.extend_from_slice(&t);
            i += 1;
        }
        out.truncate(len);
        out
    }

    /// QUIC v1 initial secret (RFC 9001 §5.2): HKDF-Extract(initial_salt, dcid) = HMAC(salt, dcid).
    pub fn quic_initial_secret(dcid: &[u8]) -> [u8; 32] {
        const SALT: [u8; 20] = [
            0x38, 0x76, 0x2c, 0xf7, 0xf5, 0x59, 0x34, 0xb3, 0x4d, 0x17, 0x9a, 0xe6, 0xa4, 0xc8, 0x0c,
            0xad, 0xcc, 0xbb, 0x7f, 0x0a,
        ];
        crate::hashtrinity::crypto::hmac_sha256(&SALT, dcid)
    }
}
pub mod scrypt {
    //! scrypt (RFC 7914) — the memory-hard password KDF (age passphrase mode, Ethereum keystores, Tarsnap).
    //! Salsa20/8 core → BlockMix → ROMix, wrapped in PBKDF2-HMAC-SHA256. Gated on the RFC 7914 known-answer.
    #![allow(clippy::needless_range_loop, clippy::manual_memcpy)]
    use crate::hashtrinity::crypto::pbkdf2_sha256;

    fn salsa20_8(b: &mut [u8; 64]) {
        let mut x = [0u32; 16];
        for i in 0..16 {
            x[i] = u32::from_le_bytes(b[i * 4..i * 4 + 4].try_into().unwrap());
        }
        let orig = x;
        let r = |a: u32, n: u32| a.rotate_left(n);
        for _ in 0..4 {
            // columns
            x[4] ^= r(x[0].wrapping_add(x[12]), 7);
            x[8] ^= r(x[4].wrapping_add(x[0]), 9);
            x[12] ^= r(x[8].wrapping_add(x[4]), 13);
            x[0] ^= r(x[12].wrapping_add(x[8]), 18);
            x[9] ^= r(x[5].wrapping_add(x[1]), 7);
            x[13] ^= r(x[9].wrapping_add(x[5]), 9);
            x[1] ^= r(x[13].wrapping_add(x[9]), 13);
            x[5] ^= r(x[1].wrapping_add(x[13]), 18);
            x[14] ^= r(x[10].wrapping_add(x[6]), 7);
            x[2] ^= r(x[14].wrapping_add(x[10]), 9);
            x[6] ^= r(x[2].wrapping_add(x[14]), 13);
            x[10] ^= r(x[6].wrapping_add(x[2]), 18);
            x[3] ^= r(x[15].wrapping_add(x[11]), 7);
            x[7] ^= r(x[3].wrapping_add(x[15]), 9);
            x[11] ^= r(x[7].wrapping_add(x[3]), 13);
            x[15] ^= r(x[11].wrapping_add(x[7]), 18);
            // rows
            x[1] ^= r(x[0].wrapping_add(x[3]), 7);
            x[2] ^= r(x[1].wrapping_add(x[0]), 9);
            x[3] ^= r(x[2].wrapping_add(x[1]), 13);
            x[0] ^= r(x[3].wrapping_add(x[2]), 18);
            x[6] ^= r(x[5].wrapping_add(x[4]), 7);
            x[7] ^= r(x[6].wrapping_add(x[5]), 9);
            x[4] ^= r(x[7].wrapping_add(x[6]), 13);
            x[5] ^= r(x[4].wrapping_add(x[7]), 18);
            x[11] ^= r(x[10].wrapping_add(x[9]), 7);
            x[8] ^= r(x[11].wrapping_add(x[10]), 9);
            x[9] ^= r(x[8].wrapping_add(x[11]), 13);
            x[10] ^= r(x[9].wrapping_add(x[8]), 18);
            x[12] ^= r(x[15].wrapping_add(x[14]), 7);
            x[13] ^= r(x[12].wrapping_add(x[15]), 9);
            x[14] ^= r(x[13].wrapping_add(x[12]), 13);
            x[15] ^= r(x[14].wrapping_add(x[13]), 18);
        }
        for i in 0..16 {
            b[i * 4..i * 4 + 4].copy_from_slice(&x[i].wrapping_add(orig[i]).to_le_bytes());
        }
    }

    fn block_mix(b: &[u8], r: usize) -> Vec<u8> {
        let mut x = [0u8; 64];
        x.copy_from_slice(&b[(2 * r - 1) * 64..]);
        let mut out = vec![0u8; 128 * r];
        for i in 0..2 * r {
            for k in 0..64 {
                x[k] ^= b[i * 64 + k];
            }
            salsa20_8(&mut x);
            // even i -> first half, odd i -> second half
            let dst = if i % 2 == 0 {
                (i / 2) * 64
            } else {
                (r + i / 2) * 64
            };
            out[dst..dst + 64].copy_from_slice(&x);
        }
        out
    }

    fn ro_mix(b: &mut [u8], r: usize, n: usize) {
        let mut v = vec![0u8; 128 * r * n];
        let mut x = b.to_vec();
        for i in 0..n {
            v[i * 128 * r..(i + 1) * 128 * r].copy_from_slice(&x);
            x = block_mix(&x, r);
        }
        for _ in 0..n {
            // integerify: last 64-byte block, first u32 (LE) mod N
            let j = u32::from_le_bytes(
                x[(2 * r - 1) * 64..(2 * r - 1) * 64 + 4]
                    .try_into()
                    .unwrap(),
            ) as usize
                % n;
            for k in 0..128 * r {
                x[k] ^= v[j * 128 * r + k];
            }
            x = block_mix(&x, r);
        }
        b.copy_from_slice(&x);
    }

    /// scrypt (RFC 7914). `n` = CPU/memory cost (power of two), `r` = block size, `p` = parallelism.
    pub fn scrypt(
        password: &[u8],
        salt: &[u8],
        n: usize,
        r: usize,
        p: usize,
        dk_len: usize,
    ) -> Vec<u8> {
        let mut b = pbkdf2_sha256(password, salt, 1, p * 128 * r);
        for i in 0..p {
            ro_mix(&mut b[i * 128 * r..(i + 1) * 128 * r], r, n);
        }
        pbkdf2_sha256(password, &b, 1, dk_len)
    }
}
pub use p384::{ecdsa_p384_sign, ecdsa_p384_verify};
pub mod rsa {
    //! RSA signature verification — PKCS#1 v1.5 + SHA-256, at 2048 and 4096 bits. Verify is `s^e mod n`
    //! (public exponent 65537 = 17 squarings, the effectively-O(1) closure — the honest party never runs
    //! the private exponent) followed by the padding/DigestInfo check: the one-cell friction verdict, a
    //! forged signature convicts. Variable-width bignum (`Vec<u64>`), zero-dep outside `hashtrinity`.
    //! Unlocks real-world RSA x509 chains (most CA roots are RSA). Also holds RSA key GENERATION
    //! (Miller-Rabin primality + extended-Euclidean modular inverse) and a masquerade of the `rsa`
    //! crate's object API, at the bottom of the file.
    use core::cmp::Ordering;

    type Bn = Vec<u64>; // little-endian limbs

    fn bn_from_be(b: &[u8]) -> Bn {
        let mut bytes = b.to_vec();
        while bytes.len() % 8 != 0 {
            bytes.insert(0, 0);
        }
        let n = bytes.len() / 8;
        let mut r = vec![0u64; n];
        for i in 0..n {
            r[i] = u64::from_be_bytes(bytes[(n - 1 - i) * 8..(n - i) * 8].try_into().unwrap());
        }
        r
    }
    fn bn_trim(a: &mut Bn) {
        while a.len() > 1 && *a.last().unwrap() == 0 {
            a.pop();
        }
    }
    fn bn_cmp(a: &Bn, b: &Bn) -> Ordering {
        let m = a.len().max(b.len());
        for i in (0..m).rev() {
            let (av, bv) = (*a.get(i).unwrap_or(&0), *b.get(i).unwrap_or(&0));
            if av != bv {
                return av.cmp(&bv);
            }
        }
        Ordering::Equal
    }
    fn bn_ge(a: &Bn, b: &Bn) -> bool {
        bn_cmp(a, b) != Ordering::Less
    }
    fn bn_mul(a: &Bn, b: &Bn) -> Bn {
        let mut r = vec![0u64; a.len() + b.len()];
        for i in 0..a.len() {
            let mut cr = 0u128;
            for j in 0..b.len() {
                let t = a[i] as u128 * b[j] as u128 + r[i + j] as u128 + cr;
                r[i + j] = t as u64;
                cr = t >> 64;
            }
            let mut k = i + b.len();
            while cr != 0 {
                let t = r[k] as u128 + cr;
                r[k] = t as u64;
                cr = t >> 64;
                k += 1;
            }
        }
        bn_trim(&mut r);
        r
    }
    fn bn_sub(a: &mut [u64], b: &Bn) {
        let mut br = 0i128;
        for i in 0..a.len() {
            let bv = *b.get(i).unwrap_or(&0) as i128;
            let v = a[i] as i128 - bv - br;
            if v < 0 {
                a[i] = (v + (1i128 << 64)) as u64;
                br = 1;
            } else {
                a[i] = v as u64;
                br = 0;
            }
        }
    }
    /// Reduce `x mod m` by binary long division (correct, width-generic).
    fn bn_mod(x: &Bn, m: &Bn) -> Bn {
        let mut rem = vec![0u64; m.len() + 1];
        let nbits = x.len() * 64;
        for i in (0..nbits).rev() {
            let bit = (x[i / 64] >> (i % 64)) & 1;
            let mut c = bit;
            for l in rem.iter_mut() {
                let nc = *l >> 63;
                *l = (*l << 1) | c;
                c = nc;
            } // <<1 | bit
            if bn_ge(&rem, m) {
                bn_sub(&mut rem, m);
            }
        }
        bn_trim(&mut rem);
        rem
    }
    /// `base^e mod m` — square-and-multiply (17 modmuls for e=65537).
    fn bn_modexp(base: &Bn, e: u64, m: &Bn) -> Bn {
        let mut r: Bn = vec![1u64];
        let mut b = bn_mod(base, m);
        let mut ee = e;
        while ee > 0 {
            if ee & 1 == 1 {
                r = bn_mod(&bn_mul(&r, &b), m);
            }
            ee >>= 1;
            if ee > 0 {
                b = bn_mod(&bn_mul(&b, &b), m);
            }
        }
        r
    }
    fn bn_to_be(a: &Bn, len: usize) -> Vec<u8> {
        let mut out = vec![0u8; len];
        for i in 0..a.len() {
            let bytes = a[i].to_le_bytes();
            for (j, &by) in bytes.iter().enumerate() {
                let pos = i * 8 + j;
                if pos < len {
                    out[len - 1 - pos] = by;
                }
            }
        }
        out
    }

    /// The SHA-256/384/512 DigestInfo DER prefixes (RFC 8017 §9.2) — same 15-byte AlgorithmIdentifier
    /// shape, differing only in the OID's last byte (01/02/03) and the trailing hash-length byte.
    const SHA256_DI: [u8; 19] = [
        0x30, 0x31, 0x30, 0x0d, 0x06, 0x09, 0x60, 0x86, 0x48, 0x01, 0x65, 0x03, 0x04, 0x02, 0x01, 0x05,
        0x00, 0x04, 0x20,
    ];
    const SHA384_DI: [u8; 19] = [
        0x30, 0x41, 0x30, 0x0d, 0x06, 0x09, 0x60, 0x86, 0x48, 0x01, 0x65, 0x03, 0x04, 0x02, 0x02, 0x05,
        0x00, 0x04, 0x30,
    ];
    const SHA512_DI: [u8; 19] = [
        0x30, 0x51, 0x30, 0x0d, 0x06, 0x09, 0x60, 0x86, 0x48, 0x01, 0x65, 0x03, 0x04, 0x02, 0x03, 0x05,
        0x00, 0x04, 0x40,
    ];

    /// General RSASSA-PKCS1-v1.5 verify, parameterized by the DigestInfo prefix — SHA-256/384/512 share
    /// this one implementation. Returns true iff `s^e mod n` decodes to `00 01 FF..FF 00 ‖ di ‖ hash`.
    fn rsa_pkcs1_verify_generic(n_be: &[u8], e: u64, sig_be: &[u8], di: &[u8], hash: &[u8]) -> bool {
        let n = bn_from_be(n_be);
        let s = bn_from_be(sig_be);
        if bn_ge(&s, &n) {
            return false;
        } // s must be in [0, n)
        let k = n_be.len();
        let em = bn_to_be(&bn_modexp(&s, e, &n), k);
        // PKCS#1 v1.5: 0x00 0x01 PS(≥8×0xFF) 0x00 T
        if em.len() < 11 || em[0] != 0x00 || em[1] != 0x01 {
            return false;
        }
        let mut i = 2;
        while i < k && em[i] == 0xff {
            i += 1;
        }
        if i < 10 || i >= k || em[i] != 0x00 {
            return false;
        } // ≥8 padding bytes, then a 00
        i += 1;
        let t = &em[i..];
        t.len() == di.len() + hash.len() && t[..di.len()] == *di && &t[di.len()..] == hash
    }
    /// Verify an RSASSA-PKCS1-v1.5 / SHA-256 signature. `n_be` = the modulus (big-endian, 256 B for 2048,
    /// 512 B for 4096), `e` = the public exponent (65537), `sig_be` = the signature, `msg_hash` = SHA-256
    /// of the message.
    pub fn rsa_pkcs1_sha256_verify(n_be: &[u8], e: u64, sig_be: &[u8], msg_hash: &[u8; 32]) -> bool {
        rsa_pkcs1_verify_generic(n_be, e, sig_be, &SHA256_DI, msg_hash)
    }
    pub fn rsa_pkcs1_sha384_verify(n_be: &[u8], e: u64, sig_be: &[u8], msg_hash: &[u8; 48]) -> bool {
        rsa_pkcs1_verify_generic(n_be, e, sig_be, &SHA384_DI, msg_hash)
    }
    pub fn rsa_pkcs1_sha512_verify(n_be: &[u8], e: u64, sig_be: &[u8], msg_hash: &[u8; 64]) -> bool {
        rsa_pkcs1_verify_generic(n_be, e, sig_be, &SHA512_DI, msg_hash)
    }

    /// `base^e mod m` with a full bignum exponent (RSA private `d`) — square-multiply over every bit of `e`.
    fn bn_modexp_big(base: &Bn, e: &Bn, m: &Bn) -> Bn {
        let mut r: Bn = vec![1u64];
        let mut b = bn_mod(base, m);
        for i in 0..e.len() * 64 {
            if (e[i / 64] >> (i % 64)) & 1 == 1 {
                r = bn_mod(&bn_mul(&r, &b), m);
            }
            b = bn_mod(&bn_mul(&b, &b), m);
        }
        r
    }

    /// General RSASSA-PKCS1-v1.5 sign: `sig = EM^d mod n`, `EM = 00 01 FF..FF 00 ‖ di ‖ hash` — the
    /// inverse of `rsa_pkcs1_verify_generic`, shared by SHA-256/384/512.
    fn rsa_pkcs1_sign_generic(n_be: &[u8], d_be: &[u8], di: &[u8], hash: &[u8]) -> Vec<u8> {
        let k = n_be.len();
        let t_len = di.len() + hash.len();
        let mut em = vec![0x00, 0x01];
        em.extend(core::iter::repeat(0xff).take(k - t_len - 3)); // PS
        em.push(0x00);
        em.extend_from_slice(di);
        em.extend_from_slice(hash);
        let sig = bn_modexp_big(&bn_from_be(&em), &bn_from_be(d_be), &bn_from_be(n_be));
        bn_to_be(&sig, k)
    }
    /// RSASSA-PKCS1-v1.5 / SHA-256 **sign**. `n_be`/`d_be` are the modulus and private exponent
    /// (big-endian). Output is the `k`-byte signature.
    pub fn rsa_pkcs1_sha256_sign(n_be: &[u8], d_be: &[u8], msg_hash: &[u8; 32]) -> Vec<u8> {
        rsa_pkcs1_sign_generic(n_be, d_be, &SHA256_DI, msg_hash)
    }
    pub fn rsa_pkcs1_sha384_sign(n_be: &[u8], d_be: &[u8], msg_hash: &[u8; 48]) -> Vec<u8> {
        rsa_pkcs1_sign_generic(n_be, d_be, &SHA384_DI, msg_hash)
    }
    pub fn rsa_pkcs1_sha512_sign(n_be: &[u8], d_be: &[u8], msg_hash: &[u8; 64]) -> Vec<u8> {
        rsa_pkcs1_sign_generic(n_be, d_be, &SHA512_DI, msg_hash)
    }

    fn bitlen(n_be: &[u8]) -> usize {
        for (i, &b) in n_be.iter().enumerate() {
            if b != 0 {
                return (n_be.len() - i) * 8 - b.leading_zeros() as usize;
            }
        }
        0
    }
    fn mgf1(seed: &[u8], len: usize) -> Vec<u8> {
        let mut out = Vec::new();
        let mut c = 0u32;
        while out.len() < len {
            let mut h = seed.to_vec();
            h.extend_from_slice(&c.to_be_bytes());
            out.extend_from_slice(&crate::hashtrinity::crypto::sha256(&h));
            c += 1;
        }
        out.truncate(len);
        out
    }
    fn emsa_pss_encode(m_hash: &[u8; 32], em_bits: usize, salt: &[u8]) -> Vec<u8> {
        let (h_len, em_len, s_len) = (32, em_bits.div_ceil(8), salt.len());
        let mut mp = vec![0u8; 8];
        mp.extend_from_slice(m_hash);
        mp.extend_from_slice(salt);
        let h = crate::hashtrinity::crypto::sha256(&mp);
        let ps_len = em_len - s_len - h_len - 2;
        let mut db = vec![0u8; ps_len];
        db.push(0x01);
        db.extend_from_slice(salt);
        let mask = mgf1(&h, em_len - h_len - 1);
        let mut mdb: Vec<u8> = db.iter().zip(mask.iter()).map(|(a, b)| a ^ b).collect();
        mdb[0] &= 0xff >> (8 * em_len - em_bits);
        let mut em = mdb;
        em.extend_from_slice(&h);
        em.push(0xbc);
        em
    }
    /// RSASSA-PSS / SHA-256 / MGF1-SHA-256 **sign** (TLS 1.3 `rsa_pss_rsae_sha256`). Deterministic when
    /// `salt` is empty; pass a random salt otherwise.
    pub fn rsa_pss_sha256_sign(n_be: &[u8], d_be: &[u8], m_hash: &[u8; 32], salt: &[u8]) -> Vec<u8> {
        let k = n_be.len();
        let em = emsa_pss_encode(m_hash, bitlen(n_be) - 1, salt);
        bn_to_be(
            &bn_modexp_big(&bn_from_be(&em), &bn_from_be(d_be), &bn_from_be(n_be)),
            k,
        )
    }
    /// RSASSA-PSS / SHA-256 verify. `s_len` = the expected salt length (0 for deterministic).
    pub fn rsa_pss_sha256_verify(
        n_be: &[u8],
        e: u64,
        sig_be: &[u8],
        m_hash: &[u8; 32],
        s_len: usize,
    ) -> bool {
        let n = bn_from_be(n_be);
        let s = bn_from_be(sig_be);
        if bn_ge(&s, &n) {
            return false;
        }
        let k = n_be.len();
        let em = bn_to_be(&bn_modexp(&s, e, &n), k);
        let em_bits = bitlen(n_be) - 1;
        let (h_len, em_len) = (32, em.len());
        if em_len < h_len + s_len + 2 || em[em_len - 1] != 0xbc {
            return false;
        }
        let (mdb, h) = (
            &em[..em_len - h_len - 1],
            &em[em_len - h_len - 1..em_len - 1],
        );
        let zbits = 8 * em_len - em_bits;
        if zbits < 8 && mdb[0] & (0xffu8 << (8 - zbits)) != 0 {
            return false;
        }
        let mask = mgf1(h, em_len - h_len - 1);
        let mut db: Vec<u8> = mdb.iter().zip(mask.iter()).map(|(a, b)| a ^ b).collect();
        db[0] &= 0xff >> zbits;
        let ps_len = em_len - h_len - s_len - 2;
        if db[..ps_len].iter().any(|&x| x != 0) || db[ps_len] != 0x01 {
            return false;
        }
        let mut mp = vec![0u8; 8];
        mp.extend_from_slice(m_hash);
        mp.extend_from_slice(&db[ps_len + 1..]);
        &crate::hashtrinity::crypto::sha256(&mp)[..] == h
    }

    // ── RSA key GENERATION — the one piece the sign/verify math above didn't cover ─────────────────────
    // Same `Bn` (little-endian u64 limbs), same core (`bn_mul`/`bn_sub`/`bn_mod`). The one new primitive
    // is bignum DIVISION (`bn_divmod`, `bn_mod`'s natural generalization — it already builds a quotient
    // bit by bit, just discarded before; here it's kept), plus addition and a small signed wrapper for
    // the extended Euclidean algorithm's Bezout coefficients (which go negative mid-computation even
    // though the final answer, reduced mod `phi`, doesn't).
    fn bn_from_u64(x: u64) -> Bn {
        vec![x]
    }
    fn bn_is_zero(a: &Bn) -> bool {
        a.iter().all(|&l| l == 0)
    }
    fn bn_is_even(a: &Bn) -> bool {
        a[0] & 1 == 0
    }
    fn bn_add(a: &Bn, b: &Bn) -> Bn {
        let n = a.len().max(b.len());
        let mut r = vec![0u64; n + 1];
        let mut carry = 0u128;
        for i in 0..n {
            let t = *a.get(i).unwrap_or(&0) as u128 + *b.get(i).unwrap_or(&0) as u128 + carry;
            r[i] = t as u64;
            carry = t >> 64;
        }
        r[n] = carry as u64;
        bn_trim(&mut r);
        r
    }
    fn bn_shr1(a: &Bn) -> Bn {
        let mut r = vec![0u64; a.len()];
        let mut carry = 0u64;
        for i in (0..a.len()).rev() {
            r[i] = (a[i] >> 1) | (carry << 63);
            carry = a[i] & 1;
        }
        bn_trim(&mut r);
        r
    }
    fn bn_sub1(a: &Bn) -> Bn {
        let mut r = a.clone();
        bn_sub(&mut r, &vec![1]);
        bn_trim(&mut r);
        r
    }
    /// `(x / m, x % m)` — `bn_mod`'s bit-by-bit long division, generalized to also keep the quotient
    /// (one bit per iteration, set whenever the shifted remainder is big enough to subtract `m`).
    fn bn_divmod(x: &Bn, m: &Bn) -> (Bn, Bn) {
        let mut rem = vec![0u64; m.len() + 1];
        let mut quot = vec![0u64; x.len()];
        let nbits = x.len() * 64;
        for i in (0..nbits).rev() {
            let bit = (x[i / 64] >> (i % 64)) & 1;
            let mut c = bit;
            for l in rem.iter_mut() {
                let nc = *l >> 63;
                *l = (*l << 1) | c;
                c = nc;
            }
            if bn_ge(&rem, m) {
                bn_sub(&mut rem, m);
                quot[i / 64] |= 1 << (i % 64);
            }
        }
        bn_trim(&mut rem);
        bn_trim(&mut quot);
        (quot, rem)
    }

    /// A signed bignum — only needed internally for the extended Euclidean algorithm below.
    struct SBn {
        neg: bool,
        mag: Bn,
    }
    fn sbn(mag: Bn) -> SBn {
        SBn { neg: false, mag }
    }
    fn sbn_sub(a: &SBn, b: &SBn) -> SBn {
        match (a.neg, b.neg) {
            (false, false) => {
                if bn_ge(&a.mag, &b.mag) {
                    let mut m = a.mag.clone();
                    bn_sub(&mut m, &b.mag);
                    bn_trim(&mut m);
                    SBn { neg: false, mag: m }
                } else {
                    let mut m = b.mag.clone();
                    bn_sub(&mut m, &a.mag);
                    bn_trim(&mut m);
                    SBn { neg: true, mag: m }
                }
            }
            (false, true) => SBn {
                neg: false,
                mag: bn_add(&a.mag, &b.mag),
            },
            (true, false) => SBn {
                neg: true,
                mag: bn_add(&a.mag, &b.mag),
            },
            (true, true) => sbn_sub(
                &SBn {
                    neg: false,
                    mag: b.mag.clone(),
                },
                &SBn {
                    neg: false,
                    mag: a.mag.clone(),
                },
            ),
        }
    }
    fn sbn_mul_bn(a: &SBn, b: &Bn) -> SBn {
        SBn {
            neg: a.neg,
            mag: bn_mul(&a.mag, b),
        }
    }

    /// Extended Euclidean algorithm: `e^-1 mod phi`, or `None` if `gcd(e, phi) != 1`. `e` is always small
    /// (65537) but `phi` is huge, so only the Bezout coefficient of `e` is tracked.
    fn mod_inverse(e: u64, phi: &Bn) -> Option<Bn> {
        let (mut r0, mut r1) = (phi.clone(), bn_from_u64(e));
        let (mut t0, mut t1) = (sbn(vec![0]), sbn(vec![1]));
        while !bn_is_zero(&r1) {
            let (q, r) = bn_divmod(&r0, &r1);
            r0 = r1;
            r1 = r;
            let new_t1 = sbn_sub(&t0, &sbn_mul_bn(&t1, &q));
            t0 = t1;
            t1 = new_t1;
        }
        if !(r0.len() == 1 && r0[0] == 1) {
            return None;
        } // gcd(e, phi) != 1
        let reduced = bn_mod(&t0.mag, phi);
        if t0.neg && !bn_is_zero(&reduced) {
            let mut d = phi.clone();
            bn_sub(&mut d, &reduced);
            bn_trim(&mut d);
            Some(d)
        } else {
            Some(reduced)
        }
    }

    /// Miller-Rabin primality test, `rounds` random bases. `n` must be odd.
    fn is_probable_prime(n: &Bn, rounds: usize) -> bool {
        if n.len() == 1 && (n[0] == 2 || n[0] == 3) {
            return true;
        }
        if bn_is_even(n) {
            return false;
        }
        let n1 = bn_sub1(n); // n - 1 = 2^s * d, d odd
        let mut d = n1.clone();
        let mut s = 0u32;
        while bn_is_even(&d) {
            d = bn_shr1(&d);
            s += 1;
        }
        let n_bytes = bn_to_be(n, n.len() * 8);
        'rounds: for _ in 0..rounds {
            let a = loop {
                // random base in [2, n)
                let cand = bn_mod(&bn_from_be(&crate::hashtrinity::crypto::rand_bytes(n_bytes.len())), n);
                if cand.len() > 1 || cand[0] >= 2 {
                    break cand;
                }
            };
            let mut x = bn_modexp_big(&a, &d, n);
            if x.len() == 1 && x[0] == 1 {
                continue;
            }
            if bn_cmp(&x, &n1) == Ordering::Equal {
                continue;
            }
            for _ in 1..s {
                x = bn_mod(&bn_mul(&x, &x), n);
                if bn_cmp(&x, &n1) == Ordering::Equal {
                    continue 'rounds;
                }
            }
            return false; // composite witness found
        }
        true
    }

    /// A random odd `bits`-bit candidate (top bit set for exact width, bottom bit set for oddness).
    fn random_odd_candidate(bits: usize) -> Bn {
        let nbytes = bits.div_ceil(8);
        let mut b = crate::hashtrinity::crypto::rand_bytes(nbytes);
        let excess = nbytes * 8 - bits;
        b[0] |= 0x80 >> excess; // the top bit of the `bits`-bit value
        *b.last_mut().unwrap() |= 1; // odd
        bn_from_be(&b)
    }
    /// Small-prime trial division — cheap rejection of most composites before Miller-Rabin runs.
    const SMALL_PRIMES: [u64; 30] = [
        3, 5, 7, 11, 13, 17, 19, 23, 29, 31, 37, 41, 43, 47, 53, 59, 61, 67, 71, 73, 79, 83, 89, 97,
        101, 103, 107, 109, 113, 127,
    ];
    fn gen_prime(bits: usize) -> Bn {
        loop {
            let cand = random_odd_candidate(bits);
            let divisible_by_small_prime = SMALL_PRIMES.iter().any(|&p| {
                !(cand.len() == 1 && cand[0] == p) && bn_is_zero(&bn_divmod(&cand, &bn_from_u64(p)).1)
            });
            if divisible_by_small_prime {
                continue;
            }
            if is_probable_prime(&cand, 40) {
                return cand;
            }
        }
    }

    /// Generate an RSA keypair at `bits` total modulus size (`e = 65537` fixed, standard convention).
    /// Returns `(n_be, e, d_be)` — the same big-endian byte shape `rsa_pkcs1_*_sign`/`verify` take.
    pub fn rsa_generate_key(bits: usize) -> (Vec<u8>, u64, Vec<u8>) {
        const E: u64 = 65537;
        loop {
            let p = gen_prime(bits / 2);
            let q = gen_prime(bits / 2);
            if p == q {
                continue;
            }
            let (p1, q1) = (bn_sub1(&p), bn_sub1(&q));
            if mod_inverse(E, &p1).is_none() || mod_inverse(E, &q1).is_none() {
                continue;
            } // gcd(e,p-1)=gcd(e,q-1)=1
            let n = bn_mul(&p, &q);
            let n_bits = n.len() * 64 - n.last().unwrap().leading_zeros() as usize;
            if n_bits != bits {
                continue;
            } // occasionally one bit short; retry for the exact width
            let phi = bn_mul(&p1, &q1);
            let d = match mod_inverse(E, &phi) {
                Some(d) => d,
                None => continue,
            };
            let k = bits / 8;
            return (bn_to_be(&n, k), E, bn_to_be(&d, k));
        }
    }

    // ── PKCS8 DER for the private key ────────────────────────────────────────────────────────────────
    // A SIMPLIFIED `SEQUENCE { version, n, e, d }` (no CRT params/otherPrimeInfos), wrapped in a real
    // PKCS8 `PrivateKeyInfo` envelope, reusing `certgen`'s DER encoder / `x509`'s TLV walker (same tools
    // the ed25519-compact masquerade uses). Nothing outside rauthy's own code ever parses these
    // persisted keys (only `n`/`e` — plain integers — are ever exposed publicly, via JWKS), so the full
    // RFC 8017 CRT-param structure buys no interop here; only encode/decode self-consistency and correct
    // RSA math (which any standard external JWT/JWKS verifier checks independently) matter.
    use crate::hashtrinity::crypto::certgen::{der_int, oid, seq, tlv};
    use crate::hashtrinity::crypto::x509::{der_children, der_tlv};

    const RSA_OID: [u8; 9] = [0x2a, 0x86, 0x48, 0x86, 0xf7, 0x0d, 0x01, 0x01, 0x01]; // 1.2.840.113549.1.1.1 rsaEncryption
    fn rsa_algid() -> Vec<u8> {
        seq(&[oid(&RSA_OID), tlv(0x05, &[])])
    } // AlgorithmIdentifier { OID, NULL }
    /// Strip the single `0x00` sign-guard byte `der_int` prepends when the top bit is set (never more
    /// than one), leaving the raw magnitude.
    fn trim_int(b: &[u8]) -> Vec<u8> {
        if b.len() > 1 && b[0] == 0 {
            b[1..].to_vec()
        } else {
            b.to_vec()
        }
    }

    fn rsa_to_pkcs8_der(n_be: &[u8], e: u64, d_be: &[u8]) -> Vec<u8> {
        let e_be = e.to_be_bytes();
        let e_trimmed = {
            let mut v = e_be.as_slice();
            while v.len() > 1 && v[0] == 0 {
                v = &v[1..];
            }
            v
        };
        let inner = seq(&[
            der_int(&[0]),
            der_int(n_be),
            der_int(e_trimmed),
            der_int(d_be),
        ]);
        seq(&[der_int(&[0]), rsa_algid(), tlv(0x04, &inner)])
    }
    fn rsa_from_pkcs8_der(d: &[u8]) -> Option<(Vec<u8>, u64, Vec<u8>)> {
        let (outer_tag, ocs, oce, _) = der_tlv(d, 0)?;
        if outer_tag != 0x30 {
            return None;
        }
        let children = der_children(d, ocs, oce);
        let (tag, cs, ce) = *children.get(2)?;
        if tag != 0x04 {
            return None;
        }
        let (inner_tag, ics, ice, _) = der_tlv(d, cs)?;
        if inner_tag != 0x30 || ice > ce {
            return None;
        }
        let fields = der_children(d, ics, ice);
        if fields.len() < 4 {
            return None;
        }
        let get_int = |i: usize| -> Option<Vec<u8>> {
            let (t, s, e) = *fields.get(i)?;
            if t != 0x02 {
                return None;
            }
            Some(trim_int(&d[s..e]))
        };
        let n_be = get_int(1)?;
        let e_bytes = get_int(2)?;
        let d_be = get_int(3)?;
        let mut e_val = 0u64;
        for &b in &e_bytes {
            e_val = (e_val << 8) | b as u64;
        }
        Some((n_be, e_val, d_be))
    }

    /// A masquerade of the `rsa` crate's object API (`RsaPrivateKey`/`RsaPublicKey`/`BigUint`/
    /// `Pkcs1v15Sign`/`traits::PublicKeyParts`/`pkcs1::Error`/`pkcs8::{Error, en/decode}`) over the
    /// functions above — same shape as the `ed25519_compact` masquerade in `ed25519.rs`. Key
    /// GENERATION ignores the caller-supplied RNG entirely (sovereignty: we read `/dev/urandom`
    /// ourselves via `crate::hashtrinity::crypto::rand_bytes`, not an externally-supplied generator).
    #[derive(Debug)]
    pub struct Error(pub(crate) String);
    impl core::fmt::Display for Error {
        fn fmt(&self, f: &mut core::fmt::Formatter<'_>) -> core::fmt::Result {
            write!(f, "rsa::Error: {}", self.0)
        }
    }
    impl std::error::Error for Error {}

    pub mod pkcs1 {
        #[derive(Debug)]
        pub struct Error(pub(crate) String);
        impl core::fmt::Display for Error {
            fn fmt(&self, f: &mut core::fmt::Formatter<'_>) -> core::fmt::Result {
                write!(f, "rsa::pkcs1::Error: {}", self.0)
            }
        }
        impl std::error::Error for Error {}
    }
    pub mod pkcs8 {
        #[derive(Debug)]
        pub struct Error(pub(crate) String);
        impl core::fmt::Display for Error {
            fn fmt(&self, f: &mut core::fmt::Formatter<'_>) -> core::fmt::Result {
                write!(f, "rsa::pkcs8::Error: {}", self.0)
            }
        }
        impl std::error::Error for Error {}

        pub struct Document(pub(crate) Vec<u8>);
        impl Document {
            pub fn to_bytes(&self) -> Vec<u8> {
                self.0.clone()
            }
        }

        pub trait DecodePrivateKey: Sized {
            fn from_pkcs8_der(bytes: &[u8]) -> Result<Self, Error>;
        }
        pub trait EncodePrivateKey {
            fn to_pkcs8_der(&self) -> Result<Document, Error>;
        }
    }

    pub mod sha2 {
        pub struct Sha256;
        pub struct Sha384;
        pub struct Sha512;
    }
    pub trait DigestMarker {
        const DI: &'static [u8];
    }
    impl DigestMarker for sha2::Sha256 {
        const DI: &'static [u8] = &SHA256_DI;
    }
    impl DigestMarker for sha2::Sha384 {
        const DI: &'static [u8] = &SHA384_DI;
    }
    impl DigestMarker for sha2::Sha512 {
        const DI: &'static [u8] = &SHA512_DI;
    }

    pub struct Pkcs1v15Sign {
        di: &'static [u8],
    }
    impl Pkcs1v15Sign {
        pub fn new<H: DigestMarker>() -> Self {
            Self { di: H::DI }
        }
    }

    pub mod traits {
        use super::BigUint;
        pub trait PublicKeyParts {
            fn n(&self) -> &BigUint;
            fn e(&self) -> &BigUint;
        }
    }

    /// Big-endian bytes, no leading zero byte (unless the value is zero) — everything that touches this
    /// crate's RSA math already speaks big-endian bytes (`bn_from_be`/`bn_to_be`), so this is a near-
    /// identity wrapper rather than a real arbitrary-precision integer type.
    #[derive(Clone)]
    pub struct BigUint(Vec<u8>);
    impl BigUint {
        pub fn from_bytes_be(b: &[u8]) -> Self {
            let mut v = b.to_vec();
            while v.len() > 1 && v[0] == 0 {
                v.remove(0);
            }
            if v.is_empty() {
                v.push(0);
            }
            Self(v)
        }
        pub fn to_bytes_be(&self) -> Vec<u8> {
            self.0.clone()
        }
    }

    #[derive(Clone)]
    pub struct RsaPublicKey {
        n: BigUint,
        e: BigUint,
    }
    impl RsaPublicKey {
        pub fn new(n: BigUint, e: BigUint) -> Result<Self, Error> {
            if n.0.is_empty() || e.0.is_empty() {
                return Err(Error("empty key component".into()));
            }
            Ok(Self { n, e })
        }
        fn e_u64(&self) -> u64 {
            let mut v = 0u64;
            for &b in &self.e.0 {
                v = (v << 8) | b as u64;
            }
            v
        }
        pub fn verify(&self, scheme: Pkcs1v15Sign, hash: &[u8], sig: &[u8]) -> Result<(), Error> {
            if rsa_pkcs1_verify_generic(&self.n.0, self.e_u64(), sig, scheme.di, hash) {
                Ok(())
            } else {
                Err(Error("signature verification failed".into()))
            }
        }
    }
    impl traits::PublicKeyParts for RsaPublicKey {
        fn n(&self) -> &BigUint {
            &self.n
        }
        fn e(&self) -> &BigUint {
            &self.e
        }
    }

    pub struct RsaPrivateKey {
        n_be: Vec<u8>,
        e: u64,
        d_be: Vec<u8>,
    }
    impl RsaPrivateKey {
        /// Unlike the real crate, takes no RNG — we generate our own randomness (see the module doc),
        /// so callers don't need a `rand`-crate generator at all (call sites drop their `thread_rng()`).
        pub fn new(bits: usize) -> Result<Self, Error> {
            let (n_be, e, d_be) = rsa_generate_key(bits);
            Ok(Self { n_be, e, d_be })
        }
        pub fn to_public_key(&self) -> RsaPublicKey {
            RsaPublicKey {
                n: BigUint::from_bytes_be(&self.n_be),
                e: BigUint::from_bytes_be(&self.e.to_be_bytes()),
            }
        }
        pub fn sign(&self, scheme: Pkcs1v15Sign, hash: &[u8]) -> Result<Vec<u8>, Error> {
            Ok(rsa_pkcs1_sign_generic(
                &self.n_be, &self.d_be, scheme.di, hash,
            ))
        }
        /// Mirrors the real crate's `AsRef<RsaPublicKey>` at the call site (`pk.as_ref().verify(...)`);
        /// an owned return works identically there since the result is used immediately.
        pub fn as_ref(&self) -> RsaPublicKey {
            self.to_public_key()
        }
    }
    impl pkcs8::DecodePrivateKey for RsaPrivateKey {
        fn from_pkcs8_der(bytes: &[u8]) -> Result<Self, pkcs8::Error> {
            rsa_from_pkcs8_der(bytes)
                .map(|(n_be, e, d_be)| Self { n_be, e, d_be })
                .ok_or_else(|| pkcs8::Error("malformed RSA PKCS8 DER".into()))
        }
    }
    impl pkcs8::EncodePrivateKey for RsaPrivateKey {
        fn to_pkcs8_der(&self) -> Result<pkcs8::Document, pkcs8::Error> {
            Ok(pkcs8::Document(rsa_to_pkcs8_der(
                &self.n_be, self.e, &self.d_be,
            )))
        }
    }

    #[cfg(test)]
    mod keygen_tests {
        use super::*;

        /// A small (fast-to-generate) key for round-trip testing — production code always uses
        /// 2048/3072/4096, but the math is bit-width-generic so a small key exercises the same paths.
        /// 1024 bits (128 bytes) is the floor that still fits a SHA-512 PKCS#1 v1.5 signature (needs
        /// >= 19 + 64 + 11 = 94 bytes) — 512 bits (64 bytes) mathematically cannot, for any RSA impl.
        #[test]
        fn keygen_sign_verify_round_trips_all_hash_sizes() {
            let (n_be, e, d_be) = rsa_generate_key(1024);
            let hash256 = [7u8; 32];
            let sig = rsa_pkcs1_sha256_sign(&n_be, &d_be, &hash256);
            assert!(rsa_pkcs1_sha256_verify(&n_be, e, &sig, &hash256));

            let hash384 = [9u8; 48];
            let sig384 = rsa_pkcs1_sha384_sign(&n_be, &d_be, &hash384);
            assert!(rsa_pkcs1_sha384_verify(&n_be, e, &sig384, &hash384));

            let hash512 = [3u8; 64];
            let sig512 = rsa_pkcs1_sha512_sign(&n_be, &d_be, &hash512);
            assert!(rsa_pkcs1_sha512_verify(&n_be, e, &sig512, &hash512));
        }

        #[test]
        fn tampered_signature_rejected() {
            let (n_be, e, d_be) = rsa_generate_key(512);
            let hash = [1u8; 32];
            let mut sig = rsa_pkcs1_sha256_sign(&n_be, &d_be, &hash);
            *sig.last_mut().unwrap() ^= 1;
            assert!(!rsa_pkcs1_sha256_verify(&n_be, e, &sig, &hash));
        }

        #[test]
        fn pkcs8_der_round_trips() {
            let (n_be, e, d_be) = rsa_generate_key(512);
            let der = rsa_to_pkcs8_der(&n_be, e, &d_be);
            let (n2, e2, d2) = rsa_from_pkcs8_der(&der).unwrap();
            assert_eq!(n2, n_be);
            assert_eq!(e2, e);
            // sign with the decoded d, verify against the original n/e — proves d round-tripped correctly
            let hash = [5u8; 32];
            let sig = rsa_pkcs1_sha256_sign(&n2, &d2, &hash);
            assert!(rsa_pkcs1_sha256_verify(&n_be, e, &sig, &hash));
        }

        #[test]
        fn masquerade_end_to_end() {
            use pkcs8::{DecodePrivateKey, EncodePrivateKey};
            let key = RsaPrivateKey::new(512).unwrap();
            let der = key.to_pkcs8_der().unwrap().to_bytes();
            let restored = RsaPrivateKey::from_pkcs8_der(&der).unwrap();

            let hash = [2u8; 32];
            let sig = restored
                .sign(Pkcs1v15Sign::new::<sha2::Sha256>(), &hash)
                .unwrap();
            assert!(restored
                .as_ref()
                .verify(Pkcs1v15Sign::new::<sha2::Sha256>(), &hash, &sig)
                .is_ok());

            let n = BigUint::from_bytes_be(&key.n_be);
            let e = BigUint::from_bytes_be(&key.e.to_be_bytes());
            let pubkey = RsaPublicKey::new(n, e).unwrap();
            assert!(pubkey
                .verify(Pkcs1v15Sign::new::<sha2::Sha256>(), &hash, &sig)
                .is_ok());

            // tampered signature must be rejected
            let mut bad_sig = sig.clone();
            *bad_sig.last_mut().unwrap() ^= 1;
            assert!(pubkey
                .verify(Pkcs1v15Sign::new::<sha2::Sha256>(), &hash, &bad_sig)
                .is_err());
        }
    }
}
pub use rsa::rsa_generate_key;
pub use rsa::{
    rsa_pkcs1_sha256_sign, rsa_pkcs1_sha256_verify, rsa_pss_sha256_sign, rsa_pss_sha256_verify,
};
pub use rsa::{
    rsa_pkcs1_sha384_sign, rsa_pkcs1_sha384_verify, rsa_pkcs1_sha512_sign, rsa_pkcs1_sha512_verify,
};
pub mod age {
    //! age (age-encryption.org/v1) — built entirely from primitives we already have: **X25519** (recipient
    //! key agreement), **HKDF-SHA256** (wrap + payload keys), **ChaCha20-Poly1305** (the STREAM payload +
    //! the file-key wrap), **HMAC-SHA256** (header MAC). No new crypto — age is the assembly. Zero-dep
    //! outside `hashtrinity`. Built strictly to the v1 spec; round-trip verified here, real-tool interop
    //! is the outstanding gate.
    use crate::hashtrinity::crypto::{
        chacha_poly::{chacha20poly1305_decrypt, chacha20poly1305_encrypt},
        hkdf_sha256, hmac_sha256, rand_bytes, x25519,
    };

    fn a32(s: &[u8]) -> [u8; 32] {
        let mut a = [0u8; 32];
        a.copy_from_slice(s);
        a
    }
    fn basepoint() -> [u8; 32] {
        let mut b = [0u8; 32];
        b[0] = 9;
        b
    }

    // ── standard base64, no padding (age's stanza/MAC encoding) ─────────────────────────────────────────
    const B64: &[u8; 64] = b"ABCDEFGHIJKLMNOPQRSTUVWXYZabcdefghijklmnopqrstuvwxyz0123456789+/";
    fn b64e(d: &[u8]) -> String {
        let mut s = String::new();
        let (mut acc, mut nb) = (0u32, 0u32);
        for &x in d {
            acc = (acc << 8) | x as u32;
            nb += 8;
            while nb >= 6 {
                nb -= 6;
                s.push(B64[((acc >> nb) & 63) as usize] as char);
            }
        }
        if nb > 0 {
            s.push(B64[((acc << (6 - nb)) & 63) as usize] as char);
        }
        s
    }
    fn b64d(s: &str) -> Option<Vec<u8>> {
        let v = |c: u8| -> Option<u32> {
            match c {
                b'A'..=b'Z' => Some((c - b'A') as u32),
                b'a'..=b'z' => Some((c - b'a' + 26) as u32),
                b'0'..=b'9' => Some((c - b'0' + 52) as u32),
                b'+' => Some(62),
                b'/' => Some(63),
                _ => None,
            }
        };
        let (mut acc, mut nb) = (0u32, 0u32);
        let mut o = Vec::new();
        for c in s.bytes() {
            acc = (acc << 6) | v(c)?;
            nb += 6;
            if nb >= 8 {
                nb -= 8;
                o.push((acc >> nb) as u8);
            }
        }
        Some(o)
    }

    /// An X25519 identity: `(secret, public)`. `public = X25519(secret, 9)`.
    pub fn age_keygen() -> ([u8; 32], [u8; 32]) {
        let sk = a32(&rand_bytes(32));
        let pk = x25519(&sk, &basepoint());
        (sk, pk)
    }

    fn stream_nonce(counter: u64, last: bool) -> [u8; 12] {
        let mut n = [0u8; 12];
        n[3..11].copy_from_slice(&counter.to_be_bytes());
        n[11] = last as u8;
        n
    }

    /// Encrypt to a single X25519 recipient (the age v1 file: text header + 16-byte payload nonce + the
    /// ChaCha20-Poly1305 STREAM in 64 KiB chunks).
    pub fn age_encrypt(recipient_pk: &[u8; 32], plaintext: &[u8]) -> Vec<u8> {
        let file_key = rand_bytes(16);
        // ── X25519 recipient stanza ──
        let eph_sk = a32(&rand_bytes(32));
        let eph_share = x25519(&eph_sk, &basepoint());
        let shared = x25519(&eph_sk, recipient_pk);
        let mut salt = eph_share.to_vec();
        salt.extend_from_slice(recipient_pk);
        let wrap_key = hkdf_sha256(&salt, &shared, b"age-encryption.org/v1/X25519", 32);
        let (mut body, tag) = chacha20poly1305_encrypt(&a32(&wrap_key), &[0u8; 12], &file_key, b"");
        body.extend_from_slice(&tag); // 16 + 16 = 32
                                      // ── header + MAC ──
        let header = format!(
            "age-encryption.org/v1\n-> X25519 {}\n{}\n",
            b64e(&eph_share),
            b64e(&body)
        );
        let mac_input = format!("{header}---");
        let hmac_key = hkdf_sha256(b"", &file_key, b"header", 32);
        let mac = hmac_sha256(&hmac_key, mac_input.as_bytes());
        let mut out = format!("{mac_input} {}\n", b64e(&mac)).into_bytes();
        // ── payload STREAM ──
        let nonce = rand_bytes(16);
        let pkey = a32(&hkdf_sha256(&nonce, &file_key, b"payload", 32));
        out.extend_from_slice(&nonce);
        let chunks: Vec<&[u8]> = if plaintext.is_empty() {
            vec![&[][..]]
        } else {
            plaintext.chunks(65536).collect()
        };
        for (i, chunk) in chunks.iter().enumerate() {
            let (ct, t) = chacha20poly1305_encrypt(
                &pkey,
                &stream_nonce(i as u64, i == chunks.len() - 1),
                chunk,
                b"",
            );
            out.extend_from_slice(&ct);
            out.extend_from_slice(&t);
        }
        out
    }

    /// Decrypt an age v1 file with an X25519 identity secret. `None` on any MAC/tag failure or wrong key.
    pub fn age_decrypt(identity_sk: &[u8; 32], file: &[u8]) -> Option<Vec<u8>> {
        // ── split the text header from the binary payload at the "--- <mac>\n" line ──
        let mut pos = 0usize;
        let mut lines: Vec<(usize, usize)> = Vec::new(); // (start,end) of each header line
        let (mut mac_input_end, mut payload_start, mut mac_b64) = (0usize, 0usize, String::new());
        while pos < file.len() {
            let nl = file[pos..].iter().position(|&b| b == b'\n')? + pos;
            let line = &file[pos..nl];
            if line.starts_with(b"---") {
                mac_input_end = pos + 3;
                mac_b64 = String::from_utf8(line[4.min(line.len())..].to_vec()).ok()?;
                payload_start = nl + 1;
                break;
            }
            lines.push((pos, nl));
            pos = nl + 1;
        }
        if payload_start == 0 {
            return None;
        }
        // ── find + unwrap the X25519 stanza ──
        let mut file_key: Option<Vec<u8>> = None;
        for w in lines.windows(2) {
            let l0 = std::str::from_utf8(&file[w[0].0..w[0].1]).ok()?;
            if let Some(share_b64) = l0.strip_prefix("-> X25519 ") {
                let eph_share = a32(&b64d(share_b64)?);
                let body = b64d(std::str::from_utf8(&file[w[1].0..w[1].1]).ok()?)?;
                if body.len() != 32 {
                    continue;
                }
                let my_pk = x25519(identity_sk, &basepoint());
                let shared = x25519(identity_sk, &eph_share);
                let mut salt = eph_share.to_vec();
                salt.extend_from_slice(&my_pk);
                let wrap_key = hkdf_sha256(&salt, &shared, b"age-encryption.org/v1/X25519", 32);
                let mut tag = [0u8; 16];
                tag.copy_from_slice(&body[16..]);
                if let Some(fk) =
                    chacha20poly1305_decrypt(&a32(&wrap_key), &[0u8; 12], &body[..16], &tag, b"")
                {
                    file_key = Some(fk);
                    break;
                }
            }
        }
        let file_key = file_key?;
        // ── verify the header MAC ──
        let hmac_key = hkdf_sha256(b"", &file_key, b"header", 32);
        let mac = hmac_sha256(&hmac_key, &file[..mac_input_end]);
        if b64e(&mac) != mac_b64 {
            return None;
        }
        // ── decrypt the payload STREAM ──
        let payload = &file[payload_start..];
        if payload.len() < 16 {
            return None;
        }
        let nonce = &payload[..16];
        let pkey = a32(&hkdf_sha256(nonce, &file_key, b"payload", 32));
        let body = &payload[16..];
        let chunks: Vec<&[u8]> = body.chunks(65536 + 16).collect();
        let mut out = Vec::new();
        for (i, chunk) in chunks.iter().enumerate() {
            if chunk.len() < 16 {
                return None;
            }
            let (ct, tag) = chunk.split_at(chunk.len() - 16);
            let mut t = [0u8; 16];
            t.copy_from_slice(tag);
            let pt = chacha20poly1305_decrypt(
                &pkey,
                &stream_nonce(i as u64, i == chunks.len() - 1),
                ct,
                &t,
                b"",
            )?;
            out.extend_from_slice(&pt);
        }
        Some(out)
    }

    // ── bech32 (BIP-173) — age's key display encoding, so raw keys bridge to the `age` tool ─────────────
    fn bech32_polymod(v: &[u8]) -> u32 {
        let gen = [
            0x3b6a57b2u32,
            0x26508e6d,
            0x1ea119fa,
            0x3d4233dd,
            0x2a1462b3,
        ];
        let mut chk = 1u32;
        for &x in v {
            let b = chk >> 25;
            chk = ((chk & 0x1ffffff) << 5) ^ x as u32;
            for i in 0..5 {
                if (b >> i) & 1 == 1 {
                    chk ^= gen[i];
                }
            }
        }
        chk
    }
    fn hrp_expand(hrp: &str) -> Vec<u8> {
        let mut v: Vec<u8> = hrp.bytes().map(|c| c >> 5).collect();
        v.push(0);
        v.extend(hrp.bytes().map(|c| c & 31));
        v
    }
    fn convertbits(data: &[u8]) -> Vec<u8> {
        let (mut acc, mut bits) = (0u32, 0u32);
        let mut out = Vec::new();
        for &b in data {
            acc = (acc << 8) | b as u32;
            bits += 8;
            while bits >= 5 {
                bits -= 5;
                out.push(((acc >> bits) & 31) as u8);
            }
        }
        if bits > 0 {
            out.push(((acc << (5 - bits)) & 31) as u8);
        }
        out
    }
    fn bech32_encode(hrp: &str, data: &[u8]) -> String {
        let five = convertbits(data);
        let mut values = hrp_expand(hrp);
        values.extend_from_slice(&five);
        values.extend_from_slice(&[0; 6]);
        let poly = bech32_polymod(&values) ^ 1;
        let chk: Vec<u8> = (0..6)
            .map(|i| ((poly >> (5 * (5 - i))) & 31) as u8)
            .collect();
        let cs = b"qpzry9x8gf2tvdw0s3jn54khce6mua7l";
        let mut s = String::from(hrp);
        s.push('1');
        for v in five.iter().chain(chk.iter()) {
            s.push(cs[*v as usize] as char);
        }
        s
    }
    /// The `age1…` recipient string for a raw X25519 public key.
    pub fn age_pubkey_string(pk: &[u8; 32]) -> String {
        bech32_encode("age", pk)
    }
    /// The `AGE-SECRET-KEY-1…` identity string for a raw X25519 secret.
    pub fn age_secret_string(sk: &[u8; 32]) -> String {
        bech32_encode("age-secret-key-", sk).to_uppercase()
    }
}
pub mod blake3 {
    //! BLAKE3 — the tree hash iroh's blob layer is built on (content-addressing + bao verified streaming).
    //! The compression is 7 rounds of the `g` mixing fold; chunks (1024 B) hash to chaining values that
    //! combine in a binary tree; the root compression carries the ROOT flag. Gated on the official test
    //! vectors (input byte `i` = `i % 251`). Zero-dep outside `hashtrinity`.
    #![allow(clippy::needless_range_loop)]

    const IV: [u32; 8] = [
        0x6A09E667, 0xBB67AE85, 0x3C6EF372, 0xA54FF53A, 0x510E527F, 0x9B05688C, 0x1F83D9AB, 0x5BE0CD19,
    ];
    const MSGP: [usize; 16] = [2, 6, 3, 10, 7, 0, 4, 13, 1, 11, 12, 5, 9, 14, 15, 8];
    const CHUNK_START: u32 = 1;
    const CHUNK_END: u32 = 2;
    const PARENT: u32 = 4;
    const ROOT: u32 = 8;
    /// BLAKE3's own chunk size in bytes — public so a caller of [`bao_verify_chunk`] can split a blob
    /// into the exact chunks the tree is built over (`data.chunks(CHUNK_LEN)`, the last one possibly
    /// shorter).
    pub const CHUNK_LEN: usize = 1024;
    const CHUNK: usize = CHUNK_LEN;

    fn g(s: &mut [u32; 16], a: usize, b: usize, c: usize, d: usize, mx: u32, my: u32) {
        s[a] = s[a].wrapping_add(s[b]).wrapping_add(mx);
        s[d] = (s[d] ^ s[a]).rotate_right(16);
        s[c] = s[c].wrapping_add(s[d]);
        s[b] = (s[b] ^ s[c]).rotate_right(12);
        s[a] = s[a].wrapping_add(s[b]).wrapping_add(my);
        s[d] = (s[d] ^ s[a]).rotate_right(8);
        s[c] = s[c].wrapping_add(s[d]);
        s[b] = (s[b] ^ s[c]).rotate_right(7);
    }
    fn round(s: &mut [u32; 16], m: &[u32; 16]) {
        g(s, 0, 4, 8, 12, m[0], m[1]);
        g(s, 1, 5, 9, 13, m[2], m[3]);
        g(s, 2, 6, 10, 14, m[4], m[5]);
        g(s, 3, 7, 11, 15, m[6], m[7]);
        g(s, 0, 5, 10, 15, m[8], m[9]);
        g(s, 1, 6, 11, 12, m[10], m[11]);
        g(s, 2, 7, 8, 13, m[12], m[13]);
        g(s, 3, 4, 9, 14, m[14], m[15]);
    }
    fn words(block: &[u8]) -> [u32; 16] {
        let mut buf = [0u8; 64];
        buf[..block.len()].copy_from_slice(block);
        let mut w = [0u32; 16];
        for i in 0..16 {
            w[i] = u32::from_le_bytes([buf[4 * i], buf[4 * i + 1], buf[4 * i + 2], buf[4 * i + 3]]);
        }
        w
    }
    fn compress(
        cv: &[u32; 8],
        block: &[u32; 16],
        counter: u64,
        block_len: u32,
        flags: u32,
    ) -> [u32; 16] {
        let mut s = [
            cv[0],
            cv[1],
            cv[2],
            cv[3],
            cv[4],
            cv[5],
            cv[6],
            cv[7],
            IV[0],
            IV[1],
            IV[2],
            IV[3],
            counter as u32,
            (counter >> 32) as u32,
            block_len,
            flags,
        ];
        let mut m = *block;
        for i in 0..7 {
            round(&mut s, &m);
            if i < 6 {
                let mut p = [0u32; 16];
                for j in 0..16 {
                    p[j] = m[MSGP[j]];
                }
                m = p;
            }
        }
        for i in 0..8 {
            s[i] ^= s[i + 8];
            s[i + 8] ^= cv[i];
        }
        s
    }
    fn cv8(o: &[u32; 16]) -> [u32; 8] {
        [o[0], o[1], o[2], o[3], o[4], o[5], o[6], o[7]]
    }

    /// Compress one chunk (≤1024 B) — the block chain with CHUNK_START/END flags — returning the full state.
    fn chunk_compress(chunk: &[u8], counter: u64, extra: u32) -> [u32; 16] {
        let mut cv = IV;
        let blocks: Vec<&[u8]> = if chunk.is_empty() {
            vec![&[][..]]
        } else {
            chunk.chunks(64).collect()
        };
        let nb = blocks.len();
        let mut out = [0u32; 16];
        for (i, blk) in blocks.iter().enumerate() {
            let mut flags = 0u32;
            if i == 0 {
                flags |= CHUNK_START;
            }
            if i == nb - 1 {
                flags |= CHUNK_END | extra;
            } // ROOT belongs only on the final block
            out = compress(&cv, &words(blk), counter, blk.len() as u32, flags);
            cv = cv8(&out);
        }
        out
    }
    fn parent_compress(l: &[u32; 8], r: &[u32; 8], extra: u32) -> [u32; 16] {
        let mut block = [0u32; 16];
        block[..8].copy_from_slice(l);
        block[8..].copy_from_slice(r);
        compress(&IV, &block, 0, 64, PARENT | extra)
    }
    fn left_len(n: usize) -> usize {
        let full = (n - 1) / CHUNK;
        let mut p = 1usize;
        while p * 2 <= full {
            p *= 2;
        }
        p * CHUNK
    }
    /// A subtree's chaining value (non-root).
    fn subtree(input: &[u8], counter: u64) -> [u32; 8] {
        if input.len() <= CHUNK {
            return cv8(&chunk_compress(input, counter, 0));
        }
        let ll = left_len(input.len());
        let l = subtree(&input[..ll], counter);
        let r = subtree(&input[ll..], counter + (ll / CHUNK) as u64);
        cv8(&parent_compress(&l, &r, 0))
    }

    /// BLAKE3-256 of `input`. Bit-identical to the reference (the ROOT flag on the final compression).
    pub fn blake3(input: &[u8]) -> [u8; 32] {
        let out = if input.len() <= CHUNK {
            chunk_compress(input, 0, ROOT)
        } else {
            let ll = left_len(input.len());
            let l = subtree(&input[..ll], 0);
            let r = subtree(&input[ll..], (ll / CHUNK) as u64);
            parent_compress(&l, &r, ROOT)
        };
        let mut o = [0u8; 32];
        for i in 0..8 {
            o[4 * i..4 * i + 4].copy_from_slice(&out[i].to_le_bytes());
        }
        o
    }

    /// Incremental BLAKE3 — `new().update(a).update(b).finalize()` is bit-identical to `blake3(a ++
    /// b)` (the streaming law: `update` calls concatenate, they don't need to see the whole input up
    /// front — `Collapse.stream_exact_general`, "incremental hashing IS this theorem"). A domain-salted,
    /// multi-argument hash (`salt`, then a function name, then N args) is exactly this shape: several
    /// `update`s, one `finalize`.
    ///
    /// A plain accumulate-then-hash-once wrapper, not a chunk-at-a-time streaming state machine (the
    /// ROOT flag can only be assigned once the *whole* input is known, so any BLAKE3 `Hasher` — this
    /// one, or the reference implementation — has to buffer until `finalize()` regardless). This is
    /// the honest, simple choice for `Hasher`'s actual callers (domain-salted small-argument hashes,
    /// never a multi-gigabyte streamed file) — the buffer never grows past what a single `blake3()`
    /// call would have needed anyway.
    #[derive(Default)]
    pub struct Hasher {
        buf: Vec<u8>,
    }
    impl Hasher {
        #[must_use]
        pub fn new() -> Self {
            Self::default()
        }
        pub fn update(&mut self, data: &[u8]) -> &mut Self {
            self.buf.extend_from_slice(data);
            self
        }
        #[must_use]
        pub fn finalize(&self) -> [u8; 32] {
            blake3(&self.buf)
        }
    }

    // ── bao verified streaming (BLAKE3's Merkle-tree streaming — iroh's blob verification) ──────────────
    fn cv_bytes(cv: &[u32; 8]) -> [u8; 32] {
        let mut b = [0u8; 32];
        for i in 0..8 {
            b[4 * i..4 * i + 4].copy_from_slice(&cv[i].to_le_bytes());
        }
        b
    }
    fn cv_from_bytes(b: &[u8]) -> [u32; 8] {
        let mut cv = [0u32; 8];
        for i in 0..8 {
            cv[i] = u32::from_le_bytes([b[4 * i], b[4 * i + 1], b[4 * i + 2], b[4 * i + 3]]);
        }
        cv
    }

    fn bao_emit(input: &[u8], counter: u64, ob: &mut Vec<u8>) {
        if input.len() <= CHUNK {
            return;
        }
        let ll = left_len(input.len());
        let l = subtree(&input[..ll], counter);
        let r = subtree(&input[ll..], counter + (ll / CHUNK) as u64);
        ob.extend_from_slice(&cv_bytes(&l));
        ob.extend_from_slice(&cv_bytes(&r)); // pre-order: parent first
        bao_emit(&input[..ll], counter, ob);
        bao_emit(&input[ll..], counter + (ll / CHUNK) as u64, ob);
    }
    /// bao outboard encode: `(root, outboard)`. The outboard = 8-byte LE length + the tree's parent CVs in
    /// pre-order. `root` equals `blake3(data)`. (Original bao = 1024-B chunks; iroh's bao-tree uses 16-KiB
    /// chunk groups — the same structure at a coarser leaf, a parameter change for wire interop.)
    pub fn bao_encode(data: &[u8]) -> ([u8; 32], Vec<u8>) {
        let mut ob = (data.len() as u64).to_le_bytes().to_vec();
        bao_emit(data, 0, &mut ob);
        (blake3(data), ob)
    }
    fn bao_verify_rec(
        expected: &[u32; 8],
        input: &[u8],
        counter: u64,
        is_root: bool,
        ob: &[u8],
        pos: &mut usize,
    ) -> bool {
        if input.len() <= CHUNK {
            return cv8(&chunk_compress(
                input,
                counter,
                if is_root { ROOT } else { 0 },
            )) == *expected;
        }
        if *pos + 64 > ob.len() {
            return false;
        }
        let l = cv_from_bytes(&ob[*pos..*pos + 32]);
        let r = cv_from_bytes(&ob[*pos + 32..*pos + 64]);
        *pos += 64;
        if cv8(&parent_compress(&l, &r, if is_root { ROOT } else { 0 })) != *expected {
            return false;
        } // tamper convicts here
        let ll = left_len(input.len());
        bao_verify_rec(&l, &input[..ll], counter, false, ob, pos)
            && bao_verify_rec(
                &r,
                &input[ll..],
                counter + (ll / CHUNK) as u64,
                false,
                ob,
                pos,
            )
    }
    /// Verify `data` against a known BLAKE3 `root` using the `outboard` — the verified-streaming check. A
    /// tampered byte anywhere fails at the cell (the parent/chunk CV won't match the root). O(n), one pass.
    pub fn bao_verify(root: &[u8; 32], outboard: &[u8], data: &[u8]) -> bool {
        if outboard.len() < 8
            || u64::from_le_bytes(outboard[..8].try_into().unwrap()) != data.len() as u64
        {
            return false;
        }
        let mut pos = 8;
        bao_verify_rec(&cv_from_bytes(root), data, 0, true, outboard, &mut pos)
    }

    /// Internal (parent) nodes in a subtree spanning `n` bytes: `ceil(n/CHUNK) - 1` (0 for a single leaf
    /// chunk). Each contributes exactly 64 outboard bytes (two chaining values) in pre-order.
    fn internal_node_count(n: usize) -> usize {
        n.div_ceil(CHUNK).saturating_sub(1)
    }

    /// **Verify ONE chunk's path, not the whole tree — the streaming law applied to bao.** `bao_verify`
    /// certifies by walking every chunk (O(n)); this walks only `chunk_index`'s path to the root
    /// (O(log(total_len/CHUNK))). The tree's shape is a pure function of `total_len` (`left_len` never
    /// looks at data), so the exact pre-order byte offset of every sibling hash `chunk_index` needs is
    /// computed directly — no touching, and no even reading, any other chunk's bytes in the outboard.
    /// This is exactly "certify once (the outboard, built once by [`bao_encode`]), read at coordinate":
    /// fetching chunk `k` of a huge blob (iroh-blobs' actual access pattern) never re-derives the whole
    /// tree, only the O(log n) hashes on that one chunk's path.
    ///
    /// `chunk_index` is 0-based; `chunk_data` must be exactly that chunk's bytes (`CHUNK`-sized, except
    /// possibly the last chunk of the blob, which may be shorter).
    pub fn bao_verify_chunk(
        root: &[u8; 32],
        outboard: &[u8],
        total_len: usize,
        chunk_index: usize,
        chunk_data: &[u8],
    ) -> bool {
        if outboard.len() < 8
            || u64::from_le_bytes(outboard[..8].try_into().unwrap()) != total_len as u64
        {
            return false;
        }
        let ob = &outboard[8..];

        // Descend from the root, recording (sibling_cv, target_is_left) at each level -- root-first.
        let mut path: Vec<([u32; 8], bool)> = Vec::new();
        let (mut lo, mut hi) = (0_usize, total_len);
        let mut ob_off = 0_usize;
        let mut counter = 0_u64;
        while hi - lo > CHUNK {
            if ob_off + 64 > ob.len() {
                return false;
            }
            let l_cv = cv_from_bytes(&ob[ob_off..ob_off + 32]);
            let r_cv = cv_from_bytes(&ob[ob_off + 32..ob_off + 64]);
            let ll = left_len(hi - lo);
            if chunk_index * CHUNK < lo + ll {
                // Target is in the left subtree -- its own pre-order block starts right after this pair.
                path.push((r_cv, true));
                ob_off += 64;
                hi = lo + ll;
            } else {
                // Target is in the right subtree -- skip this pair AND all of the left subtree's nodes.
                path.push((l_cv, false));
                ob_off += 64 + 64 * internal_node_count(ll);
                counter += (ll / CHUNK) as u64;
                lo += ll;
            }
        }

        // The leaf itself carries ROOT only if the whole tree is a single chunk (no path at all).
        let mut cv = cv8(&chunk_compress(
            chunk_data,
            counter,
            if path.is_empty() { ROOT } else { 0 },
        ));
        // Fold back up: the last-pushed level is the innermost; index 0 is the true tree root.
        for (level, &(sibling, target_is_left)) in path.iter().enumerate().rev() {
            let flags = if level == 0 { ROOT } else { 0 };
            cv = if target_is_left {
                cv8(&parent_compress(&cv, &sibling, flags))
            } else {
                cv8(&parent_compress(&sibling, &cv, flags))
            };
        }
        cv == cv_from_bytes(root)
    }
}
pub use blake3::{
    bao_encode, bao_verify, bao_verify_chunk, blake3, Hasher as Blake3Hasher,
    CHUNK_LEN as BAO_CHUNK_LEN,
};

// ── SHA-256 (FIPS 180-4): compression `f` folded (`md`) over the padded blocks ────────────────────

const H256: [u32; 8] = [
    0x6a09e667, 0xbb67ae85, 0x3c6ef372, 0xa54ff53a, 0x510e527f, 0x9b05688c, 0x1f83d9ab, 0x5be0cd19,
];
const K256: [u32; 64] = [
    0x428a2f98, 0x71374491, 0xb5c0fbcf, 0xe9b5dba5, 0x3956c25b, 0x59f111f1, 0x923f82a4, 0xab1c5ed5,
    0xd807aa98, 0x12835b01, 0x243185be, 0x550c7dc3, 0x72be5d74, 0x80deb1fe, 0x9bdc06a7, 0xc19bf174,
    0xe49b69c1, 0xefbe4786, 0x0fc19dc6, 0x240ca1cc, 0x2de92c6f, 0x4a7484aa, 0x5cb0a9dc, 0x76f988da,
    0x983e5152, 0xa831c66d, 0xb00327c8, 0xbf597fc7, 0xc6e00bf3, 0xd5a79147, 0x06ca6351, 0x14292967,
    0x27b70a85, 0x2e1b2138, 0x4d2c6dfc, 0x53380d13, 0x650a7354, 0x766a0abb, 0x81c2c92e, 0x92722c85,
    0xa2bfe8a1, 0xa81a664b, 0xc24b8b70, 0xc76c51a3, 0xd192e819, 0xd6990624, 0xf40e3585, 0x106aa070,
    0x19a4c116, 0x1e376c08, 0x2748774c, 0x34b0bcb5, 0x391c0cb3, 0x4ed8aa4a, 0x5b9cca4f, 0x682e6ff3,
    0x748f82ee, 0x78a5636f, 0x84c87814, 0x8cc70208, 0x90befffa, 0xa4506ceb, 0xbef9a3f7, 0xc67178f2,
];

/// The compression round — the trinity **merge** `State × Block → State`. This is the only parameter
/// that changes between SHA-256 / SHA-512 / BLAKE3; `sha256` = folding it.
fn compress256(mut h: [u32; 8], blk: &[u8]) -> [u32; 8] {
    let mut w = [0u32; 64];
    for i in 0..16 {
        w[i] = u32::from_be_bytes([blk[i * 4], blk[i * 4 + 1], blk[i * 4 + 2], blk[i * 4 + 3]]);
    }
    for i in 16..64 {
        let s0 = w[i - 15].rotate_right(7) ^ w[i - 15].rotate_right(18) ^ (w[i - 15] >> 3);
        let s1 = w[i - 2].rotate_right(17) ^ w[i - 2].rotate_right(19) ^ (w[i - 2] >> 10);
        w[i] = w[i - 16]
            .wrapping_add(s0)
            .wrapping_add(w[i - 7])
            .wrapping_add(s1);
    }
    let (mut a, mut b, mut c, mut d, mut e, mut f, mut g, mut hh) =
        (h[0], h[1], h[2], h[3], h[4], h[5], h[6], h[7]);
    for i in 0..64 {
        let s1 = e.rotate_right(6) ^ e.rotate_right(11) ^ e.rotate_right(25);
        let ch = (e & f) ^ ((!e) & g);
        let t1 = hh
            .wrapping_add(s1)
            .wrapping_add(ch)
            .wrapping_add(K256[i])
            .wrapping_add(w[i]);
        let s0 = a.rotate_right(2) ^ a.rotate_right(13) ^ a.rotate_right(22);
        let maj = (a & b) ^ (a & c) ^ (b & c);
        let t2 = s0.wrapping_add(maj);
        hh = g;
        g = f;
        f = e;
        e = d.wrapping_add(t1);
        d = c;
        c = b;
        b = a;
        a = t1.wrapping_add(t2);
    }
    h[0] = h[0].wrapping_add(a);
    h[1] = h[1].wrapping_add(b);
    h[2] = h[2].wrapping_add(c);
    h[3] = h[3].wrapping_add(d);
    h[4] = h[4].wrapping_add(e);
    h[5] = h[5].wrapping_add(f);
    h[6] = h[6].wrapping_add(g);
    h[7] = h[7].wrapping_add(hh);
    h
}

/// **Streaming SHA-256 — the fold made incremental** (`Song.Table.put` block-by-block; the merge is
/// `compress256`, `merge_is_state_fold`). `new().update(..).finalize()`. The one-shot `sha256` is this
/// with the whole message in one `update` — byte-identical, but now a real streaming hash (no buffering
/// hack in consumers like the rustls `Context`).
#[derive(Clone)]
pub struct Sha256 {
    h: [u32; 8],
    buf: [u8; 64],
    n: usize,
    total: u64,
}
impl Default for Sha256 {
    fn default() -> Self {
        Self::new()
    }
}
impl Sha256 {
    pub fn new() -> Self {
        Self {
            h: H256,
            buf: [0; 64],
            n: 0,
            total: 0,
        }
    }
    /// Absorb bytes — compress every full 64-byte block, buffer the remainder (the incremental `put`).
    pub fn update(&mut self, mut data: &[u8]) {
        self.total = self.total.wrapping_add(data.len() as u64);
        if self.n > 0 {
            let take = (64 - self.n).min(data.len());
            self.buf[self.n..self.n + take].copy_from_slice(&data[..take]);
            self.n += take;
            data = &data[take..];
            if self.n == 64 {
                self.h = compress256(self.h, &self.buf);
                self.n = 0;
            }
        }
        while data.len() >= 64 {
            self.h = compress256(self.h, &data[..64]);
            data = &data[64..];
        }
        if !data.is_empty() {
            self.buf[..data.len()].copy_from_slice(data);
            self.n = data.len();
        }
    }
    /// The length-padded final block(s), folded in. Bit-identical to FIPS 180-4.
    pub fn finalize(self) -> [u8; 32] {
        let bits = self.total.wrapping_mul(8);
        let mut tail = self.buf[..self.n].to_vec();
        tail.push(0x80);
        while tail.len() % 64 != 56 {
            tail.push(0);
        }
        tail.extend_from_slice(&bits.to_be_bytes());
        let mut h = self.h;
        for b in tail.chunks_exact(64) {
            h = compress256(h, b);
        }
        let mut o = [0u8; 32];
        for i in 0..8 {
            o[i * 4..i * 4 + 4].copy_from_slice(&h[i].to_be_bytes());
        }
        o
    }
}

/// SHA-256 = `md`: the fold of the compression over the message. Bit-identical to FIPS 180-4.
pub fn sha256(msg: &[u8]) -> [u8; 32] {
    let mut s = Sha256::new();
    s.update(msg);
    s.finalize()
}

// ── HMAC-SHA256 (RFC 2104) = the NESTED fold ──────────────────────────────────────────────────────

/// HMAC-SHA256 = `H(opad_k ‖ H(ipad_k ‖ m))` — the nested fold, now *streaming* the message (no concat
/// allocation; the pad blocks are absorbed then `msg` flows through). RFC 4231-exact.
pub fn hmac_sha256(key: &[u8], msg: &[u8]) -> [u8; 32] {
    let mut k = [0u8; 64];
    if key.len() > 64 {
        k[..32].copy_from_slice(&sha256(key));
    } else {
        k[..key.len()].copy_from_slice(key);
    }
    let ipad: [u8; 64] = core::array::from_fn(|i| k[i] ^ 0x36);
    let opad: [u8; 64] = core::array::from_fn(|i| k[i] ^ 0x5c);
    let mut inner = Sha256::new();
    inner.update(&ipad);
    inner.update(msg);
    let mut outer = Sha256::new();
    outer.update(&opad);
    outer.update(&inner.finalize());
    outer.finalize()
}

// ── PBKDF2-HMAC-SHA256 (RFC 8018) = the ITERATED fold ─────────────────────────────────────────────

/// PBKDF2 = the fold iterated: `T_i = ⊕_{1..c} U_j`, `U_1 = HMAC(P, S‖INT32BE(i))`, `U_j = HMAC(P, U_{j-1})`.
pub fn pbkdf2_sha256(pass: &[u8], salt: &[u8], iters: u32, dklen: usize) -> Vec<u8> {
    let mut out = Vec::with_capacity(dklen);
    let mut i: u32 = 1;
    while out.len() < dklen {
        let mut msg = salt.to_vec();
        msg.extend_from_slice(&i.to_be_bytes());
        let mut u = hmac_sha256(pass, &msg);
        let mut t = u;
        for _ in 1..iters {
            u = hmac_sha256(pass, &u);
            for j in 0..32 {
                t[j] ^= u[j];
            }
        }
        out.extend_from_slice(&t);
        i += 1;
    }
    out.truncate(dklen);
    out
}

// ── HKDF-SHA256 (RFC 5869) = extract + expand ─────────────────────────────────────────────────────

/// HKDF-Extract: `PRK = HMAC(salt, IKM)` (salt defaults to 32 zero bytes). One fold.
pub fn hkdf_extract_sha256(salt: &[u8], ikm: &[u8]) -> [u8; 32] {
    if salt.is_empty() {
        hmac_sha256(&[0u8; 32], ikm)
    } else {
        hmac_sha256(salt, ikm)
    }
}

/// HKDF-Expand: `T(i) = HMAC(PRK, T(i-1)‖info‖i)`, output the first `len` bytes. The iterated fold.
pub fn hkdf_expand_sha256(prk: &[u8], info: &[u8], len: usize) -> Vec<u8> {
    let mut out = Vec::with_capacity(len);
    let mut t: Vec<u8> = Vec::new();
    let mut i: u8 = 1;
    while out.len() < len {
        let mut msg = t.clone();
        msg.extend_from_slice(info);
        msg.push(i);
        let block = hmac_sha256(prk, &msg);
        t = block.to_vec();
        out.extend_from_slice(&block);
        i = i.wrapping_add(1);
    }
    out.truncate(len);
    out
}

/// HKDF-SHA256 = extract then expand (RFC 5869).
pub fn hkdf_sha256(salt: &[u8], ikm: &[u8], info: &[u8], len: usize) -> Vec<u8> {
    hkdf_expand_sha256(&hkdf_extract_sha256(salt, ikm), info, len)
}

/// HKDF-SHA384 (RFC 5869) — the same fold, HMAC-SHA384. TLS 1.3 SHA-384 cipher suites.
pub fn hkdf_sha384(salt: &[u8], ikm: &[u8], info: &[u8], len: usize) -> Vec<u8> {
    let prk = hmac_sha384(if salt.is_empty() { &[0u8; 48] } else { salt }, ikm);
    let (mut out, mut t, mut i) = (Vec::with_capacity(len), Vec::new(), 1u8);
    while out.len() < len {
        let mut msg = t.clone();
        msg.extend_from_slice(info);
        msg.push(i);
        let block = hmac_sha384(&prk, &msg);
        t = block.to_vec();
        out.extend_from_slice(&block);
        i = i.wrapping_add(1);
    }
    out.truncate(len);
    out
}
/// HKDF-SHA512 (RFC 5869) — HMAC-SHA512 fold.
pub fn hkdf_sha512(salt: &[u8], ikm: &[u8], info: &[u8], len: usize) -> Vec<u8> {
    let prk = hmac_sha512(if salt.is_empty() { &[0u8; 64] } else { salt }, ikm);
    let (mut out, mut t, mut i) = (Vec::with_capacity(len), Vec::new(), 1u8);
    while out.len() < len {
        let mut msg = t.clone();
        msg.extend_from_slice(info);
        msg.push(i);
        let block = hmac_sha512(&prk, &msg);
        t = block.to_vec();
        out.extend_from_slice(&block);
        i = i.wrapping_add(1);
    }
    out.truncate(len);
    out
}

// ── SHA-512 (FIPS 180-4): the SAME fold, 64-bit round, 80 constants (ed25519/TLS-384 hash) ─────────

const H512: [u64; 8] = [
    0x6a09e667f3bcc908,
    0xbb67ae8584caa73b,
    0x3c6ef372fe94f82b,
    0xa54ff53a5f1d36f1,
    0x510e527fade682d1,
    0x9b05688c2b3e6c1f,
    0x1f83d9abfb41bd6b,
    0x5be0cd19137e2179,
];
const K512: [u64; 80] = [
    0x428a2f98d728ae22,
    0x7137449123ef65cd,
    0xb5c0fbcfec4d3b2f,
    0xe9b5dba58189dbbc,
    0x3956c25bf348b538,
    0x59f111f1b605d019,
    0x923f82a4af194f9b,
    0xab1c5ed5da6d8118,
    0xd807aa98a3030242,
    0x12835b0145706fbe,
    0x243185be4ee4b28c,
    0x550c7dc3d5ffb4e2,
    0x72be5d74f27b896f,
    0x80deb1fe3b1696b1,
    0x9bdc06a725c71235,
    0xc19bf174cf692694,
    0xe49b69c19ef14ad2,
    0xefbe4786384f25e3,
    0x0fc19dc68b8cd5b5,
    0x240ca1cc77ac9c65,
    0x2de92c6f592b0275,
    0x4a7484aa6ea6e483,
    0x5cb0a9dcbd41fbd4,
    0x76f988da831153b5,
    0x983e5152ee66dfab,
    0xa831c66d2db43210,
    0xb00327c898fb213f,
    0xbf597fc7beef0ee4,
    0xc6e00bf33da88fc2,
    0xd5a79147930aa725,
    0x06ca6351e003826f,
    0x142929670a0e6e70,
    0x27b70a8546d22ffc,
    0x2e1b21385c26c926,
    0x4d2c6dfc5ac42aed,
    0x53380d139d95b3df,
    0x650a73548baf63de,
    0x766a0abb3c77b2a8,
    0x81c2c92e47edaee6,
    0x92722c851482353b,
    0xa2bfe8a14cf10364,
    0xa81a664bbc423001,
    0xc24b8b70d0f89791,
    0xc76c51a30654be30,
    0xd192e819d6ef5218,
    0xd69906245565a910,
    0xf40e35855771202a,
    0x106aa07032bbd1b8,
    0x19a4c116b8d2d0c8,
    0x1e376c085141ab53,
    0x2748774cdf8eeb99,
    0x34b0bcb5e19b48a8,
    0x391c0cb3c5c95a63,
    0x4ed8aa4ae3418acb,
    0x5b9cca4f7763e373,
    0x682e6ff3d6b2b8a3,
    0x748f82ee5defb2fc,
    0x78a5636f43172f60,
    0x84c87814a1f0ab72,
    0x8cc702081a6439ec,
    0x90befffa23631e28,
    0xa4506cebde82bde9,
    0xbef9a3f7b2c67915,
    0xc67178f2e372532b,
    0xca273eceea26619c,
    0xd186b8c721c0c207,
    0xeada7dd6cde0eb1e,
    0xf57d4f7fee6ed178,
    0x06f067aa72176fba,
    0x0a637dc5a2c898a6,
    0x113f9804bef90dae,
    0x1b710b35131c471b,
    0x28db77f523047d84,
    0x32caab7b40c72493,
    0x3c9ebe0a15c9bebc,
    0x431d67c49c100d4c,
    0x4cc5d4becb3e42b6,
    0x597f299cfc657e2a,
    0x5fcb6fab3ad6faec,
    0x6c44198c4a475817,
];

fn compress512(mut h: [u64; 8], blk: &[u8]) -> [u64; 8] {
    let mut w = [0u64; 80];
    for i in 0..16 {
        w[i] = u64::from_be_bytes(blk[i * 8..i * 8 + 8].try_into().unwrap());
    }
    for i in 16..80 {
        let s0 = w[i - 15].rotate_right(1) ^ w[i - 15].rotate_right(8) ^ (w[i - 15] >> 7);
        let s1 = w[i - 2].rotate_right(19) ^ w[i - 2].rotate_right(61) ^ (w[i - 2] >> 6);
        w[i] = w[i - 16]
            .wrapping_add(s0)
            .wrapping_add(w[i - 7])
            .wrapping_add(s1);
    }
    let (mut a, mut b, mut c, mut d, mut e, mut f, mut g, mut hh) =
        (h[0], h[1], h[2], h[3], h[4], h[5], h[6], h[7]);
    for i in 0..80 {
        let s1 = e.rotate_right(14) ^ e.rotate_right(18) ^ e.rotate_right(41);
        let ch = (e & f) ^ ((!e) & g);
        let t1 = hh
            .wrapping_add(s1)
            .wrapping_add(ch)
            .wrapping_add(K512[i])
            .wrapping_add(w[i]);
        let s0 = a.rotate_right(28) ^ a.rotate_right(34) ^ a.rotate_right(39);
        let maj = (a & b) ^ (a & c) ^ (b & c);
        let t2 = s0.wrapping_add(maj);
        hh = g;
        g = f;
        f = e;
        e = d.wrapping_add(t1);
        d = c;
        c = b;
        b = a;
        a = t1.wrapping_add(t2);
    }
    h[0] = h[0].wrapping_add(a);
    h[1] = h[1].wrapping_add(b);
    h[2] = h[2].wrapping_add(c);
    h[3] = h[3].wrapping_add(d);
    h[4] = h[4].wrapping_add(e);
    h[5] = h[5].wrapping_add(f);
    h[6] = h[6].wrapping_add(g);
    h[7] = h[7].wrapping_add(hh);
    h
}

const H384: [u64; 8] = [
    0xcbbb9d5dc1059ed8,
    0x629a292a367cd507,
    0x9159015a3070dd17,
    0x152fecd8f70e5939,
    0x67332667ffc00b31,
    0x8eb44a8768581511,
    0xdb0c2e0d64f98fa7,
    0x47b5481dbefa4fa4,
];

/// **Streaming SHA-512/384 — the same fold, 128-byte blocks, 128-bit length.** `new()` = 512,
/// `new_384()` = the 384 IV. The incremental `put`; the one-shot `sha512`/`sha384` feed one `update`.
#[derive(Clone)]
pub struct Sha512 {
    h: [u64; 8],
    buf: [u8; 128],
    n: usize,
    total: u128,
}
impl Default for Sha512 {
    fn default() -> Self {
        Self::new()
    }
}
impl Sha512 {
    pub fn new() -> Self {
        Self {
            h: H512,
            buf: [0; 128],
            n: 0,
            total: 0,
        }
    }
    pub fn new_384() -> Self {
        Self {
            h: H384,
            buf: [0; 128],
            n: 0,
            total: 0,
        }
    }
    pub fn update(&mut self, mut data: &[u8]) {
        self.total = self.total.wrapping_add(data.len() as u128);
        if self.n > 0 {
            let take = (128 - self.n).min(data.len());
            self.buf[self.n..self.n + take].copy_from_slice(&data[..take]);
            self.n += take;
            data = &data[take..];
            if self.n == 128 {
                self.h = compress512(self.h, &self.buf);
                self.n = 0;
            }
        }
        while data.len() >= 128 {
            self.h = compress512(self.h, &data[..128]);
            data = &data[128..];
        }
        if !data.is_empty() {
            self.buf[..data.len()].copy_from_slice(data);
            self.n = data.len();
        }
    }
    fn finish(self, out: usize) -> Vec<u8> {
        let bits = self.total.wrapping_mul(8);
        let mut tail = self.buf[..self.n].to_vec();
        tail.push(0x80);
        while tail.len() % 128 != 112 {
            tail.push(0);
        }
        tail.extend_from_slice(&bits.to_be_bytes());
        let mut h = self.h;
        for b in tail.chunks_exact(128) {
            h = compress512(h, b);
        }
        let mut o = Vec::with_capacity(64);
        for w in &h {
            o.extend_from_slice(&w.to_be_bytes());
        }
        o.truncate(out);
        o
    }
    pub fn finalize(self) -> [u8; 64] {
        let mut o = [0u8; 64];
        o.copy_from_slice(&self.finish(64));
        o
    }
    pub fn finalize_384(self) -> [u8; 48] {
        let mut o = [0u8; 48];
        o.copy_from_slice(&self.finish(48));
        o
    }
}

/// SHA-512 = `md` at the 64-bit round. Bit-identical to FIPS 180-4.
pub fn sha512(msg: &[u8]) -> [u8; 64] {
    let mut s = Sha512::new();
    s.update(msg);
    s.finalize()
}
/// SHA-384 = SHA-512's fold with the 384 IV, truncated to 48 bytes. The P-384 hash.
pub fn sha384(msg: &[u8]) -> [u8; 48] {
    let mut s = Sha512::new_384();
    s.update(msg);
    s.finalize_384()
}

/// HMAC-SHA512 = the nested fold at 128-byte blocks, streaming the message. RFC 4231-exact.
pub fn hmac_sha512(key: &[u8], msg: &[u8]) -> [u8; 64] {
    let mut k = [0u8; 128];
    if key.len() > 128 {
        k[..64].copy_from_slice(&sha512(key));
    } else {
        k[..key.len()].copy_from_slice(key);
    }
    let ipad: [u8; 128] = core::array::from_fn(|i| k[i] ^ 0x36);
    let opad: [u8; 128] = core::array::from_fn(|i| k[i] ^ 0x5c);
    let mut inner = Sha512::new();
    inner.update(&ipad);
    inner.update(msg);
    let mut outer = Sha512::new();
    outer.update(&opad);
    outer.update(&inner.finalize());
    outer.finalize()
}

/// HMAC-SHA384 (128-byte block, SHA-384 output) — the SHA-384 HKDF for TLS 1.3's AES-256-GCM suite.
pub fn hmac_sha384(key: &[u8], msg: &[u8]) -> [u8; 48] {
    let mut k = [0u8; 128];
    if key.len() > 128 {
        k[..48].copy_from_slice(&sha384(key));
    } else {
        k[..key.len()].copy_from_slice(key);
    }
    let ipad: [u8; 128] = core::array::from_fn(|i| k[i] ^ 0x36);
    let opad: [u8; 128] = core::array::from_fn(|i| k[i] ^ 0x5c);
    let mut inner = Sha512::new_384();
    inner.update(&ipad);
    inner.update(msg);
    let mut outer = Sha512::new_384();
    outer.update(&opad);
    outer.update(&inner.finalize_384());
    outer.finalize_384()
}

// ── MD5 (RFC 1321): the SAME Merkle–Damgård shape, an older/narrower round ───────────────────────
// Little-endian throughout (message words AND the length suffix) — the one real difference from
// SHA-256/512's big-endian convention above, not a different architecture. Not fit for anything
// collision-security-bearing; the one legitimate use left is exact compat with an external corpus
// already keyed by MD5 (e.g. a threat-intel hash blocklist) — matching, not securing.

const MD5_INIT: [u32; 4] = [0x6745_2301, 0xefcd_ab89, 0x98ba_dcfe, 0x1032_5476];
const MD5_K: [u32; 64] = [
    0xd76a_a478,
    0xe8c7_b756,
    0x2420_70db,
    0xc1bd_ceee,
    0xf57c_0faf,
    0x4787_c62a,
    0xa830_4613,
    0xfd46_9501,
    0x6980_98d8,
    0x8b44_f7af,
    0xffff_5bb1,
    0x895c_d7be,
    0x6b90_1122,
    0xfd98_7193,
    0xa679_438e,
    0x49b4_0821,
    0xf61e_2562,
    0xc040_b340,
    0x265e_5a51,
    0xe9b6_c7aa,
    0xd62f_105d,
    0x0244_1453,
    0xd8a1_e681,
    0xe7d3_fbc8,
    0x21e1_cde6,
    0xc337_07d6,
    0xf4d5_0d87,
    0x455a_14ed,
    0xa9e3_e905,
    0xfcef_a3f8,
    0x676f_02d9,
    0x8d2a_4c8a,
    0xfffa_3942,
    0x8771_f681,
    0x6d9d_6122,
    0xfde5_380c,
    0xa4be_ea44,
    0x4bde_cfa9,
    0xf6bb_4b60,
    0xbebf_bc70,
    0x289b_7ec6,
    0xeaa1_27fa,
    0xd4ef_3085,
    0x0488_1d05,
    0xd9d4_d039,
    0xe6db_99e5,
    0x1fa2_7cf8,
    0xc4ac_5665,
    0xf429_2244,
    0x432a_ff97,
    0xab94_23a7,
    0xfc93_a039,
    0x655b_59c3,
    0x8f0c_cc92,
    0xffef_f47d,
    0x8584_5dd1,
    0x6fa8_7e4f,
    0xfe2c_e6e0,
    0xa301_4314,
    0x4e08_11a1,
    0xf753_7e82,
    0xbd3a_f235,
    0x2ad7_d2bb,
    0xeb86_d391,
];
const MD5_S: [u32; 64] = [
    7, 12, 17, 22, 7, 12, 17, 22, 7, 12, 17, 22, 7, 12, 17, 22, 5, 9, 14, 20, 5, 9, 14, 20, 5, 9,
    14, 20, 5, 9, 14, 20, 4, 11, 16, 23, 4, 11, 16, 23, 4, 11, 16, 23, 4, 11, 16, 23, 6, 10, 15,
    21, 6, 10, 15, 21, 6, 10, 15, 21, 6, 10, 15, 21,
];

fn compress_md5(mut h: [u32; 4], blk: &[u8]) -> [u32; 4] {
    let mut m = [0u32; 16];
    for i in 0..16 {
        m[i] = u32::from_le_bytes([blk[i * 4], blk[i * 4 + 1], blk[i * 4 + 2], blk[i * 4 + 3]]);
    }
    let (mut a, mut b, mut c, mut d) = (h[0], h[1], h[2], h[3]);
    for i in 0..64 {
        let (f, g) = match i {
            0..=15 => ((b & c) | (!b & d), i),
            16..=31 => ((d & b) | (!d & c), (5 * i + 1) % 16),
            32..=47 => (b ^ c ^ d, (3 * i + 5) % 16),
            _ => (c ^ (b | !d), (7 * i) % 16),
        };
        let f = f.wrapping_add(a).wrapping_add(MD5_K[i]).wrapping_add(m[g]);
        a = d;
        d = c;
        c = b;
        b = b.wrapping_add(f.rotate_left(MD5_S[i]));
    }
    h[0] = h[0].wrapping_add(a);
    h[1] = h[1].wrapping_add(b);
    h[2] = h[2].wrapping_add(c);
    h[3] = h[3].wrapping_add(d);
    h
}

fn pad64_le(msg: &[u8]) -> Vec<u8> {
    let mut m = msg.to_vec();
    let bitlen = (msg.len() as u64) * 8;
    m.push(0x80);
    while m.len() % 64 != 56 {
        m.push(0);
    }
    m.extend_from_slice(&bitlen.to_le_bytes()); // little-endian length — MD5's one real divergence from SHA-256/512
    m
}

/// MD5 = the same fold, the RFC 1321 round + little-endian convention. Bit-identical to RFC 1321.
pub fn md5(msg: &[u8]) -> [u8; 16] {
    let m = pad64_le(msg);
    let h = m
        .chunks_exact(64)
        .fold(MD5_INIT, |acc, blk| compress_md5(acc, blk));
    let mut o = [0u8; 16];
    for i in 0..4 {
        o[i * 4..i * 4 + 4].copy_from_slice(&h[i].to_le_bytes());
    }
    o
}

/// Hex of bytes via hashtrinity's `ToHex` (the `hex` masquerade — no external `hex` crate).
pub fn to_hex(b: &[u8]) -> String {
    b.encode_hex::<String>()
}

/// Constant-time byte-slice compare (no early-exit timing leak on a MAC/token tag) — the
/// `subtle::ConstantTimeEq` replacement. Unequal lengths compare unequal (in non-constant time,
/// same as `subtle`: a length mismatch is not itself a secret worth protecting).
pub fn ct_eq(a: &[u8], b: &[u8]) -> bool {
    if a.len() != b.len() {
        return false;
    }
    let mut d = 0u8;
    for i in 0..a.len() {
        d |= a[i] ^ b[i];
    }
    d == 0
}
