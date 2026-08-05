//! CPU Fiat-Shamir island search driver (analysis tooling, not part of the
//! scored circuit).
//!
//! The scored op stream is byte-identical for every nonce except a fixed
//! 96-op tail (48 bits x two X;X identities) appended by `build()` when
//! `DIALOG_TAIL_NONCE` is set (see mod.rs). Only `q_target` of those 96 ops
//! varies. So we:
//!   1. build the base op stream once, strip the 96-op tail,
//!   2. pre-absorb the fixed prefix into a SHAKE256 state,
//!   3. per candidate nonce: clone the state, absorb just the 96 tail ops,
//!      finalize, derive the same shots `eval_circuit` would, and run the
//!      classical GCD prefilter on both inversion factors of every shot.
//!
//! A nonce is a *filter survivor* when zero shots are classically "hard".
//! Survivors are NECESSARY but not sufficient (phase-garbage is not modeled
//! here) — every survivor must still pass the trusted 9024-shot eval.
//!
//! Driven by a guarded test so it can use the workspace without a new [[bin]]:
//!   ISLAND_SEARCH=1 ISLAND_NONCE_START=0 ISLAND_NONCE_COUNT=64 \
//!     DIALOG_TAIL_NONCE=18100027017098 cargo test --release \
//!     -p quantum_ecc island_search_driver -- --nocapture --ignored

#![allow(dead_code)]

use crate::circuit::Op;
use crate::point_add::dialog_gcd_classical_filter::{
    check_point_add_apply_hazards, point_add_gcd_factors, sub_mod_p, DialogApplyFilterConfig,
    DialogGcdFilterConfig,
};
use crate::weierstrass_elliptic_curve::WeierstrassEllipticCurve;
use alloy_primitives::U256;
use sha3::digest::{ExtendableOutput, Update, XofReader};
use sha3::Shake256;

const NONCE_BITS: usize = 48;
const TAIL_OPS: usize = NONCE_BITS * 2;
pub const DEFAULT_SHOTS: usize = 9024;

fn secp256k1() -> WeierstrassEllipticCurve {
    WeierstrassEllipticCurve {
        modulus: crate::point_add::SECP256K1_P,
        a: U256::from(0),
        b: U256::from(7),
        gx: U256::from_str_radix(
            "79BE667EF9DCBBAC55A06295CE870B07029BFCDB2DCE28D959F2815B16F81798",
            16,
        )
        .unwrap(),
        gy: U256::from_str_radix(
            "483ADA7726A3C4655DA4FBFC0E1108A8FD17B448A68554199C47D08FFB10D4B8",
            16,
        )
        .unwrap(),
        order: U256::from_str_radix(
            "FFFFFFFFFFFFFFFFFFFFFFFFFFFFFFFEBAAEDCE6AF48A03BBFD25E8CD0364141",
            16,
        )
        .unwrap(),
    }
}

// ─── Self-contained Keccak/SHAKE256 (so we can export the absorbed sponge state
// for the CUDA port). Validated to reproduce sha3's golden k1,k2. ────────────

const KECCAK_RC: [u64; 24] = [
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
const KECCAK_ROT: [u32; 25] = [
    0, 1, 62, 28, 27, 36, 44, 6, 55, 20, 3, 10, 43, 25, 39, 41, 45, 15, 21, 8, 18, 2, 61, 56, 14,
];
// dest = y + 5*((2x+3y) mod 5) for src i = x+5y (rho+pi, x+5y lane indexing)
const KECCAK_PI: [usize; 25] = [
    0, 10, 20, 5, 15, 16, 1, 11, 21, 6, 7, 17, 2, 12, 22, 23, 8, 18, 3, 13, 14, 24, 9, 19, 4,
];

pub fn keccak_f(s: &mut [u64; 25]) {
    for round in 0..24 {
        let mut c = [0u64; 5];
        for x in 0..5 {
            c[x] = s[x] ^ s[x + 5] ^ s[x + 10] ^ s[x + 15] ^ s[x + 20];
        }
        let mut d = [0u64; 5];
        for x in 0..5 {
            d[x] = c[(x + 4) % 5] ^ c[(x + 1) % 5].rotate_left(1);
        }
        for x in 0..5 {
            for y in 0..5 {
                s[x + 5 * y] ^= d[x];
            }
        }
        // rho + pi
        let mut b = [0u64; 25];
        for i in 0..25 {
            b[KECCAK_PI[i]] = s[i].rotate_left(KECCAK_ROT[i]);
        }
        // chi
        for y in 0..5 {
            for x in 0..5 {
                s[x + 5 * y] = b[x + 5 * y] ^ ((!b[(x + 1) % 5 + 5 * y]) & b[(x + 2) % 5 + 5 * y]);
            }
        }
        // iota
        s[0] ^= KECCAK_RC[round];
    }
}

pub const SHAKE256_RATE: usize = 136; // bytes

/// Streaming Shake256 absorber matching the `sha3` crate (rate 136, pad 0x1F).
pub struct Sponge {
    pub st: [u64; 25],
    pub buf: [u8; SHAKE256_RATE],
    pub buflen: usize,
}
impl Sponge {
    pub fn new() -> Sponge {
        Sponge {
            st: [0u64; 25],
            buf: [0u8; SHAKE256_RATE],
            buflen: 0,
        }
    }
    fn absorb_block(&mut self) {
        for i in 0..(SHAKE256_RATE / 8) {
            let mut w = 0u64;
            for j in 0..8 {
                w |= (self.buf[i * 8 + j] as u64) << (8 * j);
            }
            self.st[i] ^= w;
        }
        keccak_f(&mut self.st);
    }
    pub fn absorb(&mut self, data: &[u8]) {
        for &byte in data {
            self.buf[self.buflen] = byte;
            self.buflen += 1;
            if self.buflen == SHAKE256_RATE {
                self.absorb_block();
                self.buflen = 0;
                self.buf = [0u8; SHAKE256_RATE];
            }
        }
    }
    /// Finalize (pad) and return a squeeze reader.
    pub fn finalize(mut self) -> SqueezeReader {
        self.buf[self.buflen] ^= 0x1F;
        self.buf[SHAKE256_RATE - 1] ^= 0x80;
        self.absorb_block();
        // Post-finalize state IS the first squeeze block; read from pos 0.
        SqueezeReader {
            st: self.st,
            pos: 0,
        }
    }
}
pub struct SqueezeReader {
    st: [u64; 25],
    pos: usize,
}
impl SqueezeReader {
    pub fn read(&mut self, out: &mut [u8]) {
        for o in out.iter_mut() {
            if self.pos == SHAKE256_RATE {
                keccak_f(&mut self.st);
                self.pos = 0;
            }
            let lane = self.st[self.pos / 8];
            *o = (lane >> (8 * (self.pos % 8))) as u8;
            self.pos += 1;
        }
    }
}

// ─── Fast fixed-base scalar multiplication (Jacobian comb) ──────────────────
//
// `curve.mul` is affine double-and-add with a modular inverse on every step
// (~384 inv_mod per scalar). For k·G with G FIXED we precompute a comb table
// and accumulate in Jacobian coordinates (a=0), paying a single inverse at the
// end. Parity with curve.mul is asserted in `comb_parity_ok`.

use crate::weierstrass_elliptic_curve::sub_mod;

const COMB_W: usize = 4;
const COMB_D: usize = (256 + COMB_W - 1) / COMB_W; // 64 windows
const COMB_MASK: u64 = (1 << COMB_W) - 1;

pub struct CombTable {
    p: U256,
    // t[i][j] = (j+1) * 2^(W*i) * G  (affine), j in 0..2^W-1
    t: Vec<Vec<(U256, U256)>>,
}

impl CombTable {
    pub fn new(curve: &WeierstrassEllipticCurve) -> CombTable {
        let p = curve.modulus;
        let mut t = Vec::with_capacity(COMB_D);
        for i in 0..COMB_D {
            let base = U256::from(1u64) << (COMB_W * i); // 2^(W*i)
            let mut row = Vec::with_capacity((1 << COMB_W) - 1);
            for j in 1u64..(1 << COMB_W) {
                let scalar = U256::from(j).wrapping_mul(base);
                row.push(curve.mul(curve.gx, curve.gy, scalar));
            }
            t.push(row);
        }
        CombTable { p, t }
    }

    /// Jacobian (X,Y,Z) += affine (x2,y2), a=0 (madd-2007-bl). Returns false if
    /// it hits the doubling/infinity edge (caller falls back to curve.mul).
    fn madd(&self, acc: &mut (U256, U256, U256), x2: U256, y2: U256) -> bool {
        let p = self.p;
        let (x1, y1, z1) = *acc;
        if z1.is_zero() {
            *acc = (x2, y2, U256::from(1u64));
            return true;
        }
        let z1z1 = z1.mul_mod(z1, p);
        let u2 = x2.mul_mod(z1z1, p);
        let s2 = y2.mul_mod(z1, p).mul_mod(z1z1, p);
        let h = sub_mod(u2, x1, p);
        let s2y1 = sub_mod(s2, y1, p);
        if h.is_zero() {
            return false; // same x: doubling or point at infinity — rare, fall back
        }
        let hh = h.mul_mod(h, p);
        let i = hh.mul_mod(U256::from(4u64), p);
        let j = h.mul_mod(i, p);
        let r = s2y1.mul_mod(U256::from(2u64), p);
        let v = x1.mul_mod(i, p);
        let x3 = sub_mod(
            sub_mod(r.mul_mod(r, p), j, p),
            v.mul_mod(U256::from(2u64), p),
            p,
        );
        let y3 = sub_mod(
            r.mul_mod(sub_mod(v, x3, p), p),
            y1.mul_mod(j, p).mul_mod(U256::from(2u64), p),
            p,
        );
        let z3 = sub_mod(
            sub_mod((z1.add_mod(h, p)).mul_mod(z1.add_mod(h, p), p), z1z1, p),
            hh,
            p,
        );
        *acc = (x3, y3, z3);
        true
    }

    /// k·G in affine, or None on the rare madd edge (caller uses curve.mul).
    pub fn mul(&self, k: U256) -> Option<(U256, U256)> {
        let p = self.p;
        let mut acc = (U256::ZERO, U256::ZERO, U256::ZERO); // identity (Z=0)
        let limbs = k.as_limbs(); // [u64; 4], little-endian
        for i in 0..COMB_D {
            let bit = COMB_W * i;
            let digit = ((limbs[bit / 64] >> (bit % 64)) & COMB_MASK) as usize;
            // a 4-bit window never straddles a 64-bit limb (64 % 4 == 0)
            if digit != 0 {
                let (qx, qy) = self.t[i][digit - 1];
                if !self.madd(&mut acc, qx, qy) {
                    return None;
                }
            }
        }
        let (x, y, z) = acc;
        if z.is_zero() {
            return Some((U256::ZERO, U256::ZERO));
        }
        let zinv = z.inv_mod(p).expect("Z not invertible");
        let zinv2 = zinv.mul_mod(zinv, p);
        let zinv3 = zinv2.mul_mod(zinv, p);
        Some((x.mul_mod(zinv2, p), y.mul_mod(zinv3, p)))
    }
}

/// k·G with the comb, falling back to curve.mul on the rare edge.
#[inline]
fn mul_g(comb: &CombTable, curve: &WeierstrassEllipticCurve, k: U256) -> (U256, U256) {
    match comb.mul(k) {
        Some(pt) => pt,
        None => curve.mul(curve.gx, curve.gy, k),
    }
}

/// Absorb one op exactly as `eval_circuit::fiat_shamir_seed` does.
fn absorb_op(h: &mut Shake256, op: &Op) {
    h.update(&[op.kind as u8]);
    h.update(&op.q_control2.0.to_le_bytes());
    h.update(&op.q_control1.0.to_le_bytes());
    h.update(&op.q_target.0.to_le_bytes());
    h.update(&op.c_target.0.to_le_bytes());
    h.update(&op.c_condition.0.to_le_bytes());
    h.update(&op.r_target.0.to_le_bytes());
}

/// Pre-absorbed prefix plus the two tail-op templates (target tx0 vs tx1).
pub struct PrefixState {
    hasher: Shake256,
    op_count: usize,
    tx0_op: Op,
    tx1_op: Op,
}

impl PrefixState {
    /// Build the base op stream for `base_nonce`, validate the 96-op tail, and
    /// pre-absorb everything before it.
    pub fn from_build(base_nonce: u64) -> PrefixState {
        std::env::set_var("DIALOG_TAIL_NONCE", base_nonce.to_string());
        let ops = crate::point_add::build();
        let n = ops.len();
        assert!(n > TAIL_OPS, "op stream too short for a nonce tail");
        let tail = &ops[n - TAIL_OPS..];

        // The tail is pairs of identical X ops; op 2i and 2i+1 share q_target,
        // which is tx0 when bit i of base_nonce is 0, tx1 when it is 1.
        let mut tx0_op: Option<Op> = None;
        let mut tx1_op: Option<Op> = None;
        for i in 0..NONCE_BITS {
            let a = tail[2 * i];
            let b = tail[2 * i + 1];
            assert_eq!(a.q_target.0, b.q_target.0, "tail pair {i} not identical");
            if (base_nonce >> i) & 1 == 1 {
                tx1_op.get_or_insert(a);
            } else {
                tx0_op.get_or_insert(a);
            }
        }
        let tx0_op = tx0_op.expect("base nonce had no 0 bit in low 48");
        let tx1_op = tx1_op.expect("base nonce had no 1 bit in low 48");
        assert_ne!(tx0_op.q_target.0, tx1_op.q_target.0);

        let mut hasher = Shake256::default();
        hasher.update(b"quantum_ecc-fiat-shamir-v2");
        hasher.update(&(n as u64).to_le_bytes());
        for op in &ops[..n - TAIL_OPS] {
            absorb_op(&mut hasher, op);
        }
        PrefixState {
            hasher,
            op_count: n,
            tx0_op,
            tx1_op,
        }
    }

    /// Finalized XOF for a given nonce (prefix + this nonce's 96-op tail).
    fn xof_for(&self, nonce: u64) -> sha3::Shake256Reader {
        let mut h = self.hasher.clone();
        for i in 0..NONCE_BITS {
            let op = if (nonce >> i) & 1 == 1 {
                &self.tx1_op
            } else {
                &self.tx0_op
            };
            absorb_op(&mut h, op);
            absorb_op(&mut h, op);
        }
        h.finalize_xof()
    }
}

/// Result of screening one nonce.
pub struct NonceReport {
    pub nonce: u64,
    pub shots: usize,
    pub hard: usize,
}

/// Screen one nonce: derive shots like eval and run the GCD prefilter on both
/// factors of each. `early_stop` returns as soon as `hard` exceeds it (fast
/// reject); pass `usize::MAX` to count all hard shots.
pub fn screen_nonce(
    prefix: &PrefixState,
    curve: &WeierstrassEllipticCurve,
    comb: &CombTable,
    cfg: &DialogGcdFilterConfig,
    apply_cfg: &DialogApplyFilterConfig,
    nonce: u64,
    target_shots: usize,
    early_stop: usize,
) -> NonceReport {
    let p = curve.modulus;
    let mut xof = prefix.xof_for(nonce);
    let mut shots = 0usize;
    let mut hard = 0usize;
    let mut rb = [[0u8; 32]; 2];
    for _ in 0..target_shots {
        xof.read(&mut rb[0]);
        xof.read(&mut rb[1]);
        let k1 = U256::from_le_bytes(rb[0]);
        let k2 = U256::from_le_bytes(rb[1]);
        let t = mul_g(comb, curve, k1);
        let o = mul_g(comb, curve, k2);
        if t.0 == o.0 {
            continue;
        }
        if t.0.is_zero() && t.1.is_zero() {
            continue;
        }
        if o.0.is_zero() && o.1.is_zero() {
            continue;
        }
        let e = curve.add(t.0, t.1, o.0, o.1);
        shots += 1;
        // Complete per-shot predicate: GCD transcripts (both factors) + tail
        // codec + convergence + apply forward/reverse + fold-carry escapes +
        // apply value mismatch. dx=px-qx, c=qx-rx, dy=py-qy, lambda=dy/dx.
        let (dx, c) = point_add_gcd_factors(t.0, o.0, e.0);
        let dy = sub_mod_p(t.1, o.1, p);
        let lambda = match dx.inv_mod(p) {
            Some(inv) => dy.mul_mod(inv, p),
            None => {
                hard += 1;
                if hard > early_stop {
                    break;
                }
                continue;
            }
        };
        if check_point_add_apply_hazards(dx, dy, lambda, c, cfg, apply_cfg).is_err() {
            hard += 1;
            if hard > early_stop {
                break;
            }
        }
    }
    NonceReport { nonce, shots, hard }
}

fn env_usize(key: &str, default: usize) -> usize {
    std::env::var(key)
        .ok()
        .and_then(|s| s.parse().ok())
        .unwrap_or(default)
}
fn env_u64(key: &str, default: u64) -> u64 {
    std::env::var(key)
        .ok()
        .and_then(|s| s.parse().ok())
        .unwrap_or(default)
}

/// Env-driven sweep entry point (invoked from `examples/island_search.rs`).
///
///   ISLAND_NONCE_START, ISLAND_NONCE_COUNT, ISLAND_SHOTS (default 9024),
///   ISLAND_COUNT_ALL (count every hard shot instead of early-stop),
///   DIALOG_TAIL_NONCE (the base/frontier nonce, also the self-check nonce).
pub fn run_from_env() {
    let base_nonce = env_u64("DIALOG_TAIL_NONCE", 18100027017098);
    let start = env_u64("ISLAND_NONCE_START", 0);
    let count = env_u64("ISLAND_NONCE_COUNT", 64);
    let shots = env_usize("ISLAND_SHOTS", DEFAULT_SHOTS);
    let full = std::env::var("ISLAND_COUNT_ALL").is_ok();

    // build() applies configure_ecdsafail_submission_route() (sets the knob env),
    // so call it before DialogGcdFilterConfig::from_env().
    let prefix = PrefixState::from_build(base_nonce);
    let curve0 = secp256k1();
    let comb = CombTable::new(&curve0);
    // Parity self-check: comb must agree with curve.mul on random scalars.
    {
        let mut x = U256::from(0x1234_5678_9abc_def0u64);
        for _ in 0..20000 {
            x = x
                .wrapping_mul(U256::from(6364136223846793005u64))
                .wrapping_add(U256::from(1442695040888963407u64));
            let a = comb.mul(x).unwrap();
            let b = curve0.mul(curve0.gx, curve0.gy, x);
            assert_eq!(a, b, "comb parity mismatch at k={x}");
        }
        eprintln!("comb parity OK (20000 random scalars)");
    }
    // Golden-vector export for CUDA parity. For DIALOG_TAIL_NONCE (the base
    // nonce) prints, for the first ISLAND_GOLDEN shots, every intermediate the
    // CUDA port must reproduce so each layer can be validated independently:
    //   k1 k2 | px py qx qy rx | dx c dy lambda | verdict
    // verdict = OK or the HardReason debug string.
    if let Ok(g) = std::env::var("ISLAND_GOLDEN") {
        let n: usize = g.parse().unwrap_or(256);
        let curve = secp256k1();
        let p = curve.modulus;
        let cfg = DialogGcdFilterConfig::from_env();
        let apply_cfg = DialogApplyFilterConfig::from_env();
        let mut xof = prefix.xof_for(base_nonce);
        let mut rb = [[0u8; 32]; 2];
        let mut emitted = 0usize;
        println!("# GOLDEN base_nonce={base_nonce} shots={n}");
        println!("# k1 k2 px py qx qy rx dx c dy lambda verdict");
        while emitted < n {
            xof.read(&mut rb[0]);
            xof.read(&mut rb[1]);
            let k1 = U256::from_le_bytes(rb[0]);
            let k2 = U256::from_le_bytes(rb[1]);
            let t = mul_g(&comb, &curve, k1);
            let o = mul_g(&comb, &curve, k2);
            if t.0 == o.0 || (t.0.is_zero() && t.1.is_zero()) || (o.0.is_zero() && o.1.is_zero()) {
                continue;
            }
            let e = curve.add(t.0, t.1, o.0, o.1);
            let (dx, c) = point_add_gcd_factors(t.0, o.0, e.0);
            let dy = sub_mod_p(t.1, o.1, p);
            let lambda = dx
                .inv_mod(p)
                .map(|i| dy.mul_mod(i, p))
                .unwrap_or(U256::ZERO);
            let verdict = match check_point_add_apply_hazards(dx, dy, lambda, c, &cfg, &apply_cfg) {
                Ok(_) => "OK".to_string(),
                Err(e) => format!("{e:?}").replace(' ', ""),
            };
            println!(
                "{k1:#x} {k2:#x} {:#x} {:#x} {:#x} {:#x} {:#x} {dx:#x} {c:#x} {dy:#x} {lambda:#x} {verdict}",
                t.0, t.1, o.0, o.1, e.0
            );
            emitted += 1;
        }
        return;
    }
    // Export the absorbed SHAKE prefix state + tail-op templates for the CUDA
    // port, and self-validate by reproducing the base nonce's first k1,k2.
    if std::env::var("ISLAND_EXPORT_SHAKE").is_ok() {
        std::env::set_var("DIALOG_TAIL_NONCE", base_nonce.to_string());
        let ops = crate::point_add::build();
        let n = ops.len();
        let absorb_op_my = |sp: &mut Sponge, op: &Op| {
            sp.absorb(&[op.kind as u8]);
            sp.absorb(&op.q_control2.0.to_le_bytes());
            sp.absorb(&op.q_control1.0.to_le_bytes());
            sp.absorb(&op.q_target.0.to_le_bytes());
            sp.absorb(&op.c_target.0.to_le_bytes());
            sp.absorb(&op.c_condition.0.to_le_bytes());
            sp.absorb(&op.r_target.0.to_le_bytes());
        };
        let mut sp = Sponge::new();
        sp.absorb(b"quantum_ecc-fiat-shamir-v2");
        sp.absorb(&(n as u64).to_le_bytes());
        for op in &ops[..n - TAIL_OPS] {
            absorb_op_my(&mut sp, op);
        }
        // tail templates (49 bytes each) for tx0 / tx1
        let op_bytes = |op: &Op| -> Vec<u8> {
            let mut v = vec![op.kind as u8];
            v.extend_from_slice(&op.q_control2.0.to_le_bytes());
            v.extend_from_slice(&op.q_control1.0.to_le_bytes());
            v.extend_from_slice(&op.q_target.0.to_le_bytes());
            v.extend_from_slice(&op.c_target.0.to_le_bytes());
            v.extend_from_slice(&op.c_condition.0.to_le_bytes());
            v.extend_from_slice(&op.r_target.0.to_le_bytes());
            v
        };
        let t0 = op_bytes(&prefix.tx0_op);
        let t1 = op_bytes(&prefix.tx1_op);
        println!("SHAKE_PREFIX_OPCOUNT {n}");
        println!("SHAKE_BUFLEN {}", sp.buflen);
        print!("SHAKE_STATE");
        for w in sp.st.iter() {
            print!(" {w:016x}");
        }
        println!();
        print!("SHAKE_BUF ");
        for b in sp.buf.iter() {
            print!("{b:02x}");
        }
        println!();
        print!("SHAKE_TAIL0 ");
        for b in &t0 {
            print!("{b:02x}");
        }
        println!();
        print!("SHAKE_TAIL1 ");
        for b in &t1 {
            print!("{b:02x}");
        }
        println!();
        // self-validate: absorb base nonce tail, finalize, squeeze 2 shots, print k1,k2
        let mut sp2 = Sponge {
            st: sp.st,
            buf: sp.buf,
            buflen: sp.buflen,
        };
        for i in 0..NONCE_BITS {
            let tb = if (base_nonce >> i) & 1 == 1 { &t1 } else { &t0 };
            sp2.absorb(tb);
            sp2.absorb(tb);
        }
        let mut rd = sp2.finalize();
        for _ in 0..2 {
            let mut rb = [0u8; 32];
            rd.read(&mut rb);
            let k = U256::from_le_bytes(rb);
            println!("SHAKE_SELFCHECK_K {k:#x}");
        }
        return;
    }
    if std::env::var("ISLAND_DUMP_ENV").is_ok() {
        for k in [
            "DIALOG_GCD_APPLY_CLEAN_COMPARE_BITS",
            "DIALOG_GCD_COMPARE_BITS",
            "DIALOG_GCD_FOLD_CARRY_TRUNC_W",
            "KAL_DOUBLE_CARRY_TRUNC_W",
            "KAL_FOLD_CARRY_TRUNC_W",
            "DIALOG_GCD_SPECIAL_FOLD_PARK_LOW_CARRIES",
            "SQUARE_ROW_WINDOW_CLEAN_COMPARE_BITS",
            "DIALOG_GCD_WIDTH_MARGIN",
            "DIALOG_GCD_WIDTH_SLOPE_X1000",
            "DIALOG_GCD_ACTIVE_ITERATIONS",
            "SQUARE_ROW_MAX_SEG",
        ] {
            eprintln!("ENV {k} = {:?}", std::env::var(k).ok());
        }
        return;
    }
    let cfg = DialogGcdFilterConfig::from_env();
    let apply_cfg = DialogApplyFilterConfig::from_env();
    // Export the per-step GCD schedule arrays + flags for the CUDA predicate.
    if std::env::var("ISLAND_EXPORT_SCHED").is_ok() {
        let ai = cfg.active_iterations;
        println!("SCHED_ACTIVE_ITERS {ai}");
        println!(
            "SCHED_FLAGS odd={} k2={} k2force0={} matsub={} skipedge={}",
            cfg.odd_u_lowbit_fastpath as u8,
            cfg.k2 as u8,
            cfg.k2_force0 as u8,
            cfg.raw_tobitvector_materialized_sub as u8,
            cfg.skip_zero_edge_tobit_fwd_cshift as u8
        );
        let aw: Vec<usize> = (0..ai).map(|s| cfg.active_width(s)).collect();
        let cb: Vec<usize> = (0..ai)
            .map(|s| cfg.compare_bits_for_step(s, aw[s]))
            .collect();
        let csw: Vec<usize> = (0..ai).map(|s| cfg.cswap_width(aw[s], s)).collect();
        let bw: Vec<usize> = (0..ai)
            .map(|s| cfg.body_carry_trunc_width_fast(aw[s], s))
            .collect();
        let shw: Vec<usize> = (0..ai).map(|s| cfg.shift_width(aw[s], s)).collect();
        let pr = |name: &str, v: &[usize]| {
            print!("{name}");
            for x in v {
                print!(" {x}");
            }
            println!();
        };
        pr("SCHED_AW", &aw);
        pr("SCHED_CB", &cb);
        pr("SCHED_CSW", &csw);
        pr("SCHED_BW", &bw);
        pr("SCHED_SHW", &shw);
        return;
    }
    let curve = secp256k1();

    // CPU batch-confirm: read candidate nonces (one per line) from ISLAND_CONFIRM
    // file, run the EXACT full predicate on each, print the true survivors (hard=0).
    if let Ok(path) = std::env::var("ISLAND_CONFIRM") {
        let text = std::fs::read_to_string(&path).expect("read ISLAND_CONFIRM file");
        let cands: Vec<u64> = text
            .lines()
            .filter_map(|l| l.trim().parse::<u64>().ok())
            .collect();
        eprintln!(
            "confirming {} candidates with full predicate ({} shots)",
            cands.len(),
            shots
        );
        use std::sync::atomic::{AtomicUsize, Ordering as O};
        use std::sync::Mutex;
        let idx = AtomicUsize::new(0);
        let clean: Mutex<Vec<u64>> = Mutex::new(Vec::new());
        let nthreads = env_usize(
            "ISLAND_THREADS",
            std::thread::available_parallelism()
                .map(|n| n.get())
                .unwrap_or(1),
        );
        std::thread::scope(|sc| {
            for _ in 0..nthreads.max(1) {
                sc.spawn(|| loop {
                    let i = idx.fetch_add(1, O::Relaxed);
                    if i >= cands.len() {
                        break;
                    }
                    let r =
                        screen_nonce(&prefix, &curve, &comb, &cfg, &apply_cfg, cands[i], shots, 0);
                    if r.hard == 0 {
                        clean.lock().unwrap().push(cands[i]);
                        println!("CONFIRMED {}", cands[i]);
                    }
                });
            }
        });
        let mut c = clean.into_inner().unwrap();
        c.sort_unstable();
        eprintln!(
            "confirmed {} true survivors of {} candidates",
            c.len(),
            cands.len()
        );
        return;
    }
    eprintln!(
        "prefix ready: op_count={} base_nonce={} shots={} sweeping [{}, {})",
        prefix.op_count,
        base_nonce,
        shots,
        start,
        start + count
    );

    // Soundness self-check: the base nonce is eval-clean (0/0/0), so it MUST be
    // a filter survivor (0 hard). A nonzero count means the prefilter is
    // over-strict (false rejects) and the search would miss real survivors.
    let base = screen_nonce(
        &prefix,
        &curve,
        &comb,
        &cfg,
        &apply_cfg,
        base_nonce,
        shots,
        usize::MAX,
    );
    eprintln!(
        "[base] nonce={} shots={} hard={}  (expect hard=0)",
        base.nonce, base.shots, base.hard
    );

    let early = if full { usize::MAX } else { 0 };
    let threads = env_usize(
        "ISLAND_THREADS",
        std::thread::available_parallelism()
            .map(|n| n.get())
            .unwrap_or(1),
    );
    let near = env_usize("ISLAND_REPORT_NEAR", 0); // also log nonces with hard <= near

    use std::sync::atomic::{AtomicU64, Ordering};
    use std::sync::Mutex;
    let next = AtomicU64::new(start);
    let endx = start + count;
    let survivors: Mutex<Vec<u64>> = Mutex::new(Vec::new());
    let best: Mutex<(u64, usize)> = Mutex::new((0, usize::MAX)); // (nonce, min hard seen)
    let tot_hard = AtomicU64::new(0);
    let tot_shots = AtomicU64::new(0);

    std::thread::scope(|scope| {
        for _ in 0..threads.max(1) {
            scope.spawn(|| loop {
                let nonce = next.fetch_add(1, Ordering::Relaxed);
                if nonce >= endx {
                    break;
                }
                let r = screen_nonce(
                    &prefix, &curve, &comb, &cfg, &apply_cfg, nonce, shots, early,
                );
                if r.hard == 0 {
                    survivors.lock().unwrap().push(r.nonce);
                    eprintln!("[SURVIVOR] nonce={} shots={}", r.nonce, r.shots);
                }
                if full {
                    tot_hard.fetch_add(r.hard as u64, Ordering::Relaxed);
                    tot_shots.fetch_add(r.shots as u64, Ordering::Relaxed);
                    let mut b = best.lock().unwrap();
                    if r.hard < b.1 {
                        *b = (r.nonce, r.hard);
                    }
                    if near > 0 && r.hard <= near {
                        eprintln!("[near] nonce={} hard={}/{}", r.nonce, r.hard, r.shots);
                    }
                }
            });
        }
    });

    let mut survivors = survivors.into_inner().unwrap();
    survivors.sort_unstable();
    if full {
        let b = best.into_inner().unwrap();
        let th = tot_hard.load(Ordering::Relaxed) as f64;
        let ts = tot_shots.load(Ordering::Relaxed) as f64;
        let h = if ts > 0.0 { th / ts } else { 0.0 };
        // Per-nonce density estimate: probability all ~9024 shots are GCD-clean.
        let avg_shots = ts / count as f64;
        let density = (1.0 - h).powf(avg_shots);
        eprintln!("best (fewest hard): nonce={} hard={}", b.0, b.1);
        eprintln!(
            "mean hard-rate h={:.6e} over {} shots; GCD-clean density ~= (1-h)^{:.0} = {:.3e}  (~1 survivor / {:.3e} nonces)",
            h, ts as u64, avg_shots, density, if density > 0.0 { 1.0 / density } else { f64::INFINITY }
        );
    }
    eprintln!(
        "swept {} nonces on {} threads, {} survivors ({:.6}% survival)",
        count,
        threads,
        survivors.len(),
        100.0 * survivors.len() as f64 / count as f64
    );
    for s in &survivors {
        println!("SURVIVOR {}", s);
    }
}
