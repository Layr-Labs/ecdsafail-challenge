//! Reversible unpacked PZ inversion as a bit-by-bit pipelined state machine
//! (design reference: `scripts/kaliski_test.py` `pz_big_step`). This supersedes
//! the full-division `shrunken_pz_primitives` module, whose coarser granularity
//! needed a fat quotient pad and did not handle large termination quotients.
//!
//! Per iteration (fixed count ~= sum of quotient bitlengths), gated on the state
//! flags so termination is intrinsic (no separate counter):
//!   DIVISION substep:  s = bitlen(A)-bitlen(B); align B<<s; if A>=B { A-=B;
//!                      `q_div` ^= 1<<s }; restore B>>s. A<B => `div_active=0`.
//!   MULTIPLY substep (pipelined): s = `ctz(q_mul)`; clear it; a += b<<s; restore.
//!                      `q_mul==0` => swap a,b; flip parity; `mul_active=0`.
//!   TRANSITION: q_div->q_mul; swap A,B; divide builds the NEXT quotient while
//!               the multiply drains the PREVIOUS. q pads are TINY (one quotient).
//! All shifts are `controlled_cyclic_rotate` (rotate-in-place, fixed width).
//! Up front: normalize x -> min(x, P-x) (sgn); final a corrected by parity ^ sgn.

#![allow(dead_code)]

use crate::circuit::{Op, OperationType, QubitId, NO_QUBIT};
use crate::point_add::B;
use crate::point_add::trailmix_port::circuit::{Circuit, QReg};
use crate::point_add::trailmix_port::inversion::q944_dirty_parity_microkernels::{
    controlled_add_dirty_carry_refs, controlled_sub_dirty_carry_refs,
    strict_compare_gated_dirty_carry_refs,
};
use crate::point_add::trailmix_port::inversion::q944_full_structural::{
    q944_full_gate_route, Q944FullGateRoute, Q944_GATE_HOST_CENSUS_COMMIT,
    Q944_GATE_HOST_CENSUS_JOB, Q944_GATE_HOST_CENSUS_TREE, Q944_QUOTIENT_WITNESS_BLOB,
    Q944_QUOTIENT_WITNESS_COMMIT, Q944_QUOTIENT_WITNESS_JOB, Q944_QUOTIENT_WITNESS_TREE,
};
use crate::point_add::trailmix_port::inversion::q944_quotient_witness::{
    q944_clear_non_sentinel_shift, q944_commit_parked_sentinel,
    q944_partial_demux_excluding_sentinel, q944_reverse_materialize_non_sentinel_index,
    q944_reverse_park_sentinel, Q944_QUOTIENT_SENTINEL, Q944_QUOTIENT_WIDTH,
    Q944_SHIFT_WIDTH,
};
use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::{
    borrow_compare_gated_not_refs_with_carry, borrow_compare_gated_refs,
    borrow_compare_gated_refs_with_carry, borrow_compare_refs, borrow_compare_refs_with_carry,
};
use super::q945_local_hosts::{
    assert_q945_static_host_table, q945_carry_route, q945_hclz_route, Q945CarryRoute,
    Q945HclzForm, Q945HclzRoute, Q945Host, Q945StateRegister, Q945Substep, Q945_HCLZ_ROWS,
    Q945_NON_HCLZ_ROWS,
};

fn env_usize(name: &str, default: usize) -> usize {
    std::env::var(name)
        .ok()
        .and_then(|s| s.parse::<usize>().ok())
        .unwrap_or(default)
}

fn trailmix_srot_width() -> usize {
    // The generated schedule's shift bounds need six bits on valid samples.
    // Keep an env override for experiments.
    env_usize("TRAILMIX_SROT_W", 6).max(1)
}

fn q954_srot_counter7_requested() -> bool {
    std::env::var("LOWQ_Q954_SROT_COUNTER7").ok().as_deref() == Some("1")
}

fn q949_affine_counter_requested() -> bool {
    std::env::var("LOWQ_Q949_AFFINE_COUNTER").ok().as_deref() == Some("1")
}

fn borrowed_transcript_experiment_requested() -> bool {
    std::env::var("LOWQ_BORROWED_TRANSCRIPT_EXPERIMENT")
        .ok()
        .as_deref()
        == Some("1")
}

fn reverse_ca255_relational_loan_requested() -> bool {
    std::env::var("LOWQ_REVERSE_CA255_RELATIONAL_LOAN_EXPERIMENT")
        .ok()
        .as_deref()
        == Some("1")
}

fn passenger_top_lifetime_experiment_requested() -> bool {
    std::env::var("LOWQ_PASSENGER_TOP_LIFETIME_EXPERIMENT")
        .ok()
        .as_deref()
        == Some("1")
}

fn q947_passenger_direct_hclz_requested() -> bool {
    std::env::var("LOWQ_Q947_PASSENGER_DIRECT_HCLZ")
        .ok()
        .as_deref()
        == Some("1")
}

fn q946_second_ownership_release_requested() -> bool {
    std::env::var("LOWQ_Q946_SECOND_OWNERSHIP_RELEASE")
        .ok()
        .as_deref()
        == Some("1")
}

fn q945_local_hosts_requested() -> bool {
    std::env::var("LOWQ_Q945_LOCAL_HOSTS").ok().as_deref() == Some("1")
}

fn q945_dirty_parity_arithmetic_requested() -> bool {
    std::env::var("LOWQ_Q945_DIRTY_PARITY_ARITHMETIC")
        .ok()
        .as_deref()
        == Some("1")
}

fn q944_full_structural_requested() -> bool {
    std::env::var("LOWQ_Q944_FULL_STRUCTURAL").ok().as_deref() == Some("1")
}

fn q944_residual_one_lane_cut_requested() -> bool {
    std::env::var("LOWQ_Q944_RESIDUAL_ONE_LANE_CUT")
        .ok()
        .as_deref()
        == Some("1")
}

fn lowq_q945_local_hosts_enabled() -> bool {
    if !q945_local_hosts_requested() {
        return false;
    }
    assert!(
        q946_second_ownership_release_requested(),
        "Q945 local hosts require the Q946 ownership route"
    );
    assert_eq!(
        std::env::var("LOWQ_Q956_OFF_BORROW").ok().as_deref(),
        Some("1"),
        "Q945 local hosts require the Q946 off alias"
    );
    use std::sync::OnceLock;
    static CHECKED: OnceLock<()> = OnceLock::new();
    CHECKED.get_or_init(|| {
        let report = assert_q945_static_host_table();
        assert_eq!(report.borrowed_hclz_sites, 208);
        assert_eq!(report.direct_hclz_sites, 16);
        assert_eq!(report.hclz_events, 224);
    });
    true
}

fn lowq_q945_dirty_parity_arithmetic_enabled() -> bool {
    if !q945_dirty_parity_arithmetic_requested() {
        return false;
    }
    assert!(
        lowq_q945_local_hosts_enabled(),
        "Q945 dirty-parity arithmetic requires the Q945 local-host route"
    );
    true
}

fn lowq_q944_full_structural_enabled() -> bool {
    if !q944_full_structural_requested() {
        return false;
    }
    assert!(
        lowq_q945_dirty_parity_arithmetic_enabled(),
        "Q944 full structural route requires Q945 dirty-parity arithmetic"
    );
    assert!(
        lowq_q959_selective_borrow_enabled(),
        "Q944 full structural route requires selective borrowing"
    );
    assert_eq!(
        trailmix_srot_width(),
        5,
        "Q944 quotient witness requires five owned shift lanes"
    );
    use std::sync::OnceLock;
    static CHECKED: OnceLock<()> = OnceLock::new();
    CHECKED.get_or_init(|| {
        let report = super::q944_full_structural::assert_q944_full_static_route();
        assert_eq!(report.classes, 14);
        assert_eq!(report.ordinary_sites, 36);
        assert_eq!(report.quotient_sites, 20);
        assert_eq!(report.total_sites, 56);
    });
    true
}

fn lowq_q944_residual_one_lane_cut_enabled() -> bool {
    if !q944_residual_one_lane_cut_requested() {
        return false;
    }
    assert!(
        lowq_q944_full_structural_enabled(),
        "Q944 residual cut requires the full structural Q944 route"
    );
    true
}

fn q949_robust_symmetric_schedule_requested() -> bool {
    let requested = super::shrunken_pz_schedule::q949_robust_symmetric_schedule_requested();
    assert!(
        !requested || q949_affine_counter_requested(),
        "LOWQ_Q949_ROBUST_SYMMETRIC_SCHEDULE requires LOWQ_Q949_AFFINE_COUNTER=1"
    );
    requested
}

fn trailmix_logical_srot_width() -> usize {
    trailmix_srot_width() + usize::from(q954_srot_counter7_requested())
}

fn trailmix_counter_width() -> usize {
    if q949_affine_counter_requested() {
        1
    } else if std::env::var("TRAILMIX_NO_COUNTER").ok().as_deref() == Some("1") {
        0
    } else {
        env_usize("TRAILMIX_COUNTER_W", 10)
    }
}

fn trailmix_q_width(wq: usize) -> usize {
    let w = wq.max(1);
    std::env::var("TRAILMIX_Q_CAP")
        .ok()
        .and_then(|s| s.parse::<usize>().ok())
        .map_or(w, |cap| w.min(cap.max(1)))
}

/// Per-step quotient width with SELECTIVE peak-targeting.
///
/// The global qubit peak at a `shrunken_pz` step is
///   2*max(wa,wb) + 2*max(wca,wcb) + q_width + FIXED.
/// A blunt global `TRAILMIX_Q_CAP` clamps q on ALL ~490 steps (most have
/// universal q in 23..38), but only the peak-binding step(s) need a smaller q
/// to lower the global peak. Clamping the rest just manufactures classical
/// misses (overflowed quotients) without helping the peak.
///
/// `TRAILMIX_Q_TARGET=T` instead gives each step a budget so that its working
/// width never exceeds T: `q <= T - 2*max(wa,wb) - 2*max(wca,wcb)`. Steps whose
/// other registers are small keep their full natural q (no miss); only the
/// wide-carry peak step(s) get q trimmed, and only by the minimum needed.
/// Falls back to `trailmix_q_width` (global cap) when `TRAILMIX_Q_TARGET` unset.
/// Cap the shared A/B register width (both A and B are resized to max(wa,wb)).
/// `TRAILMIX_AB_CAP` trims it on the steps where it would otherwise bind the peak.
fn trailmix_ab_width(wab: usize) -> usize {
    let w = wab.max(1);
    std::env::var("TRAILMIX_AB_CAP")
        .ok()
        .and_then(|s| s.parse::<usize>().ok())
        .map_or(w, |c| w.min(c.max(1)))
}

/// Cap the shared ca/cb cofactor register width (both resized to max(wca,wcb)).
/// `TRAILMIX_CACB_CAP` trims the dominant 2*245 carry pair at the peak step.
fn trailmix_cacb_width(wcacb: usize) -> usize {
    let w = wcacb.max(1);
    std::env::var("TRAILMIX_CACB_CAP")
        .ok()
        .and_then(|s| s.parse::<usize>().ok())
        .map_or(w, |c| w.min(c.max(1)))
}

/// Fuse the immutable input-sign bit into the EEA parity bit and reclaim the
/// released persistent wire. If `s` is the
/// input sign and `p` is the original EEA parity, the fused state is `s XOR p`.
/// The slope-correction control is therefore its negation, and reverse EEA
/// restores `s XOR 1`, from which `s` is recovered and uncomputed exactly.
fn sign_parity_q_reuse_enabled() -> bool {
    if std::env::var("TRAILMIX_SIGN_PARITY_Q_REUSE")
        .ok()
        .as_deref()
        != Some("1")
    {
        return false;
    }
    assert!(
        matches!(
            std::env::var("TRAILMIX_Q_TARGET").ok().as_deref(),
            Some("683" | "684")
        ),
        "TRAILMIX_SIGN_PARITY_Q_REUSE is sealed to Q_TARGET=683/684"
    );
    true
}

fn trailmix_q_width_step(wq: usize, wa: usize, wb: usize, wca: usize, wcb: usize) -> usize {
    let natural = wq.max(1);
    let target = std::env::var("TRAILMIX_Q_TARGET")
        .ok()
        .and_then(|s| s.parse::<usize>().ok());
    let Some(target) = target else {
        return trailmix_q_width(wq);
    };
    // q budget is computed from the (possibly capped) A/B and ca/cb widths so the
    // working width 2*ab + 2*cacb + q meets `target` consistently with the resizes.
    let other = 2 * trailmix_ab_width(wa.max(wb)) + 2 * trailmix_cacb_width(wca.max(wcb));
    // Q_TARGET=684 retains the audited quotient widths. The two reclaimed
    // persistent lanes are physical savings and are not added back to q.
    let budget = target.saturating_sub(other).max(1);
    // Still honor a global Q_CAP if both are set (take the tighter bound).
    let capped = natural.min(budget);
    std::env::var("TRAILMIX_Q_CAP")
        .ok()
        .and_then(|s| s.parse::<usize>().ok())
        .map_or(capped, |cap| capped.min(cap.max(1)))
        .max(1)
}

fn trailmix_register_widths_step(i: usize) -> [usize; 5] {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::{
        q949_effective_reg_widths, reg_widths,
    };

    if q949_affine_counter_requested() {
        return q949_effective_reg_widths(i);
    }

    let (wa, wb, wca, wcb, wq) = reg_widths(i);
    let ab = trailmix_ab_width(wa.max(wb));
    let cacb = trailmix_cacb_width(wca.max(wcb));
    let q = trailmix_q_width_step(wq, wa, wb, wca, wcb);
    [ab, ab, cacb, cacb, q]
}

fn trailmix_register_los_step(i: usize) -> [usize; 5] {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::{
        q949_effective_reg_los, reg_los,
    };

    if q949_affine_counter_requested() {
        q949_effective_reg_los(i)
    } else {
        let (a, b, ca, cb, q) = reg_los(i);
        [a, b, ca, cb, q]
    }
}

fn compute_active(c: &mut Circuit, counter: &[QReg], candidates: &[&QReg]) -> QReg {
    let active = c.alloc_qreg("active");
    if counter.is_empty() {
        c.x(&active);
    } else if lowq_q959_selective_borrow_enabled() {
        toggle_zero_dirty(c, counter, &active, candidates, &[&active]);
    } else {
        or_is_zero(c, counter, &active);
    }
    active
}

fn uncompute_active(c: &mut Circuit, counter: &[QReg], active: &QReg, candidates: &[&QReg]) {
    if counter.is_empty() {
        c.x(active);
    } else if lowq_q959_selective_borrow_enabled() {
        toggle_zero_dirty(c, counter, active, candidates, &[active]);
    } else {
        or_is_zero(c, counter, active);
    }
}

/// `p + 1` (secp256k1 base field prime) as 33 LE bytes.
fn p_plus_1_bytes() -> Vec<u8> {
    vec![
        0x30, 0xfc, 0xff, 0xff, 0xfe, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0x00,
    ]
}

/// Controlled field-negate `a := (p - a) mod p` IFF `g` (a in [0,p), 257-bit).
/// Self-inverse. `~a + (p+1) ≡ p - a (mod 2^257)`; canonical for a in [1,p).
/// (Relocated from `kaliski_spooky::unpacked` so `shrunken_pz` has no spooky-Kaliski dep.)
pub fn controlled_field_neg(c: &mut Circuit, g: &QReg, a: &[QReg]) {
    use crate::point_add::trailmix_port::arith::const_add::controlled_add_const;
    for q in a {
        c.cx(g, q);
    }
    controlled_add_const(c, g, a, &p_plus_1_bytes());
}

/// Canonical controlled field negation. Unlike `controlled_field_neg`, this
/// leaves zero at zero when the control is set instead of producing the
/// congruent but noncanonical representative `p`.
fn controlled_field_neg_canonical(c: &mut Circuit, g: &QReg, a: &[QReg]) {
    assert_eq!(a.len(), 257, "canonical field negation requires 257 lanes");
    let nonzero = c.alloc_qreg("field-neg.nonzero");
    let apply = c.alloc_qreg("field-neg.apply");
    or_nonzero(c, a, &nonzero);
    c.ccx(g, &nonzero, &apply);
    controlled_field_neg(c, &apply, a);
    c.ccx(g, &nonzero, &apply);
    or_nonzero(c, a, &nonzero);
    c.zero_and_free(apply);
    c.zero_and_free(nonzero);
}

/// `s += bitlen(a) - bitlen(b)` (clz diff), bound by `bound`. After alignment in
/// the division substep, s is the shift to apply. Inverse: swap a,b.
/// LEAN `bit_length`: `s += bitlen(src)` (or `-=` if dec), via a reversible
/// prefix-AND ladder + gray-code deposit -- ~2n ccx (ladder build+unbuild) with
/// NO per-row position-equality. Supersedes the first-hit scan (~38 tof/row from
/// the per-row `toggle_on_cursor_eq_const` uncompute of `is_hit`).
///
/// Construction (MSB-first running flag `f_i` = "no 1 bit strictly above i"):
///   - prefix-AND ladder over ~src (X-bracketed) gives every `f_i` as a ladder
///     qubit, fully reversibly (fwd builds, rev unbuilds).
///   - deposit pos (init = n) ^= (i ^ (i+1)) gated on `f_i`, for i = n-1..0. The
///     gray differences telescope: pos collapses to the MSB index p (= bitlen-1).
///   - s += (pos + 1)  [bitlen]; then uncompute pos (re-run deposit) + ladder.
///
/// PRE: src nonzero (EEA gcd / nonzero quotient pad). For src==0 this returns
/// bitlen=1 (pos stays 0, +1); callers must not pass an all-zero src.
/// _middle core. Builds the prefix-AND ladder over ~src, deposits the MSB index
/// (= bitlen-1) into the caller's `pos` register (PRE: pos = |n>) in the FORWARD
/// sweep, runs `body` (which sees pos = MSB index), then unbuilds.
///
/// `body` returns whether the deposit should be UNDONE on the reverse sweep:
///   - `false` (DEFAULT, 3n): pos is KEPT at the MSB index -- the caller owns it
///     and must clear it later (e.g. via the SM's reverse). One consume = 3n.
///   - `true` (4n): the deposit is re-run on the reverse, returning pos to |n>.
///     Use when pos is a throwaway temp whose value was folded elsewhere in body.
///
/// The gray-code deposit is pure XOR (CX gated on a single flag materialized from
/// the prefix-AND with one ccx, then HMR-freed) -- so each consume is 1 toffoli
/// per position. Prefix build+unbuild = 2n; consume = n/sweep.
fn bit_length_lean_middle(
    circ: &mut Circuit,
    src: &[&QReg],
    pos: &[QReg],
    body: impl FnOnce(&mut Circuit) -> bool,
) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::{kg_prefix_ancilla_count, KgPrefixAnd};
    let n = src.len();
    if n == 0 {
        body(circ);
        return;
    }
    // ~src (X-bracket); the prefix-AND reads the complemented bits.
    for q in src {
        circ.x(q);
    }
    // q = ~src MSB-first: q[j] = ~src[n-1-j]. The log*-ancilla KG streaming
    // prefix-AND gives, at layer i, AND(ctrls) = AND(q[0..i]) = "no 1 in top i
    // positions" = f_k ("no 1 strictly above k") for k = n-1-i. ctrls is 1-2 qubits
    // (KG conditionally-clean form), so the deposit is the KG prefix-controlled-X
    // consumer directly: CX (1 ctrl, zero toffoli) or CCX (2 ctrls) per gray bit --
    // NO mcx materialize. Total ~3n-4n (2n prefix compute + n-2n consume).
    let qbits: Vec<&QReg> = src.iter().rev().copied().collect();
    let nanc = kg_prefix_ancilla_count(n);
    let anc_owned = circ.alloc_qreg_bits("bll.kganc", nanc);
    let anc: Vec<&QReg> = anc_owned.iter().collect();
    let flag = circ.alloc_qreg("bll.flag");

    // Deposit at layer i (position k = n-1-i): gray-XOR (k ^ (k+1)) into pos gated
    // on f_k = AND(ctrls). For a 2-qubit ctrls, materialize f_k onto `flag` with ONE
    // ccx, CX the gray bits (free), then free `flag` via clear_and (HMR + cz_if_bit,
    // ZERO toffoli) -- so the consume is 1 toffoli/position. For <=1 ctrl the gray
    // bits are a direct CX/X (zero toffoli). pos starts at |n>; the gray differences
    // telescope it to the MSB index p. Self-inverse, so reverse undoes pos to |n>.
    fn deposit_step(
        circ: &mut Circuit,
        i: usize,
        ctrls: &[&QReg],
        pos: &[QReg],
        flag: &QReg,
        n: usize,
    ) {
        if i >= n {
            return; // i == n is the empty (k = -1) layer
        }
        let k = n - 1 - i;
        let gd = k ^ (k + 1);
        let bits: Vec<usize> = (0..pos.len()).filter(|&b| (gd >> b) & 1 == 1).collect();
        if bits.is_empty() {
            return;
        }
        match ctrls {
            [] => {
                for &b in &bits {
                    circ.x(&pos[b]);
                }
            }
            [c] => {
                for &b in &bits {
                    circ.cx(c, &pos[b]);
                }
            }
            [a, b2] => {
                circ.ccx(a, b2, flag); // flag = f_k (1 toffoli)
                for &b in &bits {
                    circ.cx(flag, &pos[b]); // free
                }
                circ.clear_and(flag, a, b2); // free flag via HMR+CZ (0 toffoli)
            }
            _ => unreachable!("KG prefix ctrls is <=2 qubits"),
        }
    }

    let kg = KgPrefixAnd::new(&qbits, &anc);
    let done = kg.forward(circ, |c, i, ctrls| deposit_step(c, i, ctrls, pos, &flag, n)); // pos -> p
    let clean = body(circ);
    if clean {
        // 4n: re-run the deposit on the reverse, returning pos to |n>.
        done.reverse(circ, |c, i, ctrls| deposit_step(c, i, ctrls, pos, &flag, n));
    } else {
        // 3n: unbuild the prefix only; pos stays at the MSB index (caller-owned).
        done.reverse(circ, |_, _, _| {});
    }
    circ.zero_and_free(flag);
    drop(anc);
    for q in anc_owned {
        circ.zero_and_free(q);
    }
    for q in src {
        circ.x(q);
    }
}

fn lowq_direct_prefix_bitlen_requested() -> bool {
    std::env::var("LOWQ_DIRECT_PREFIX_BITLEN")
        .ok()
        .as_deref()
        == Some("1")
}

fn lowq_direct_prefix_dirty_update_requested() -> bool {
    std::env::var("LOWQ_DIRECT_PREFIX_DIRTY_UPDATE")
        .ok()
        .as_deref()
        == Some("1")
}

fn lowq_direct_prefix_no_flag_requested() -> bool {
    std::env::var("LOWQ_DIRECT_PREFIX_NO_FLAG")
        .ok()
        .as_deref()
        == Some("1")
}

pub(crate) fn lowq_fused_zero_prefix_bitlen_requested() -> bool {
    std::env::var("LOWQ_FUSED_ZERO_PREFIX_BITLEN")
        .ok()
        .as_deref()
        == Some("1")
}

/// Opt-in exact reversal for allocation-free KG decrements that borrow their
/// clean prefix ancillae from the caller.
pub const CALLER_SCRATCH_KG_REVERSE_DECREMENT_FLAG: &str =
    "LOWQ_CALLER_SCRATCH_KG_REVERSE_DECREMENT";

#[must_use]
pub fn caller_scratch_kg_reverse_decrement_requested() -> bool {
    std::env::var(CALLER_SCRATCH_KG_REVERSE_DECREMENT_FLAG)
        .ok()
        .as_deref()
        == Some("1")
}

pub(crate) const DIRECT_PREFIX_KG_SCRATCH_LEN: usize = 5;
pub(crate) const DIRECT_PREFIX_INCREMENT_SCRATCH_LEN: usize = 3;
pub(crate) const DIRECT_PREFIX_FULL_SCRATCH_LEN: usize =
    DIRECT_PREFIX_KG_SCRATCH_LEN + DIRECT_PREFIX_INCREMENT_SCRATCH_LEN + 1;
pub(crate) const DIRECT_PREFIX_COMPACT_SCRATCH_LEN: usize =
    DIRECT_PREFIX_KG_SCRATCH_LEN + DIRECT_PREFIX_INCREMENT_SCRATCH_LEN;
pub(crate) const DIRECT_PREFIX_COMPACT7_SCRATCH_LEN: usize =
    DIRECT_PREFIX_KG_SCRATCH_LEN + 2;

fn assert_direct_prefix_full_scratch(
    src: &[&QReg],
    target: &[QReg],
    scratch: &[&QReg],
) {
    assert_eq!(
        scratch.len(),
        DIRECT_PREFIX_FULL_SCRATCH_LEN,
        "direct-prefix full scratch requires exactly {DIRECT_PREFIX_FULL_SCRATCH_LEN} lanes"
    );
    for (index, lane) in scratch.iter().enumerate() {
        assert!(
            scratch[..index]
                .iter()
                .all(|other| other.id() != lane.id()),
            "direct-prefix full scratch lane {index} aliases an earlier scratch lane"
        );
        assert!(
            src.iter().all(|source| source.id() != lane.id()),
            "direct-prefix full scratch lane {index} aliases the source"
        );
        assert!(
            target.iter().all(|target| target.id() != lane.id()),
            "direct-prefix full scratch lane {index} aliases the target"
        );
    }
}

fn assert_direct_prefix_compact_scratch(
    src: &[&QReg],
    target: &[QReg],
    scratch: &[&QReg],
) {
    assert_eq!(
        scratch.len(),
        DIRECT_PREFIX_COMPACT_SCRATCH_LEN,
        "direct-prefix compact scratch requires exactly {DIRECT_PREFIX_COMPACT_SCRATCH_LEN} lanes"
    );
    for (index, lane) in scratch.iter().enumerate() {
        assert!(
            scratch[..index]
                .iter()
                .all(|other| other.id() != lane.id()),
            "direct-prefix compact scratch lane {index} aliases an earlier scratch lane"
        );
        assert!(
            src.iter().all(|source| source.id() != lane.id()),
            "direct-prefix compact scratch lane {index} aliases the source"
        );
        assert!(
            target.iter().all(|target| target.id() != lane.id()),
            "direct-prefix compact scratch lane {index} aliases the target"
        );
    }
}

fn assert_direct_prefix_compact7_scratch(
    src: &[&QReg],
    target: &[QReg],
    scratch: &[&QReg],
) {
    assert_eq!(
        scratch.len(),
        DIRECT_PREFIX_COMPACT7_SCRATCH_LEN,
        "direct-prefix compact7 scratch requires exactly {DIRECT_PREFIX_COMPACT7_SCRATCH_LEN} lanes"
    );
    assert_eq!(
        target.len(),
        4,
        "direct-prefix compact7 scratch is sealed to four-bit targets"
    );
    for (index, lane) in scratch.iter().enumerate() {
        assert!(
            scratch[..index]
                .iter()
                .all(|other| other.id() != lane.id()),
            "direct-prefix compact7 scratch lane {index} aliases an earlier scratch lane"
        );
        assert!(
            src.iter().all(|source| source.id() != lane.id()),
            "direct-prefix compact7 scratch lane {index} aliases the source"
        );
        assert!(
            target.iter().all(|target| target.id() != lane.id()),
            "direct-prefix compact7 scratch lane {index} aliases the target"
        );
    }
}

fn assert_fused_zero_prefix_preconditions(
    src: &[&QReg],
    target: &[QReg],
    dirty_updates: bool,
    no_materialized_flag: bool,
    increment_scratch: &[&QReg],
    full_scratch: Option<&[&QReg]>,
    omitted_high_bits: usize,
) {
    assert_eq!(
        std::env::var("LOWQ_DIRECT_PREFIX_BITLEN").ok().as_deref(),
        Some("1"),
        "LOWQ_FUSED_ZERO_PREFIX_BITLEN requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    assert!(
        !target.is_empty(),
        "fused zero-prefix bit length requires a nonempty target"
    );
    let target_capacity = 1usize.checked_shl(target.len() as u32);
    let target_is_wide_enough = target_capacity.is_none_or(|capacity| src.len() < capacity);
    let split_high_is_wide_enough = omitted_high_bits > 0
        && target_capacity.is_none_or(|capacity| {
            capacity
                .checked_shl(omitted_high_bits as u32)
                .is_none_or(|split_capacity| src.len() < split_capacity)
        });
    assert!(
        target_is_wide_enough || split_high_is_wide_enough,
        "fused zero-prefix target width {} cannot represent source width {}",
        target.len(),
        src.len()
    );
    assert!(
        !no_materialized_flag || dirty_updates,
        "LOWQ_DIRECT_PREFIX_NO_FLAG requires LOWQ_DIRECT_PREFIX_DIRTY_UPDATE=1"
    );

    for (index, lane) in src.iter().enumerate() {
        assert!(
            src[..index].iter().all(|other| other.id() != lane.id()),
            "fused zero-prefix source lane {index} aliases an earlier source lane"
        );
        assert!(
            target.iter().all(|other| other.id() != lane.id()),
            "fused zero-prefix source lane {index} aliases the target"
        );
    }
    for (index, lane) in target.iter().enumerate() {
        assert!(
            target[..index]
                .iter()
                .all(|other| other.id() != lane.id()),
            "fused zero-prefix target lane {index} aliases an earlier target lane"
        );
    }
    for (index, lane) in increment_scratch.iter().enumerate() {
        assert!(
            increment_scratch[..index]
                .iter()
                .all(|other| other.id() != lane.id()),
            "fused zero-prefix increment scratch lane {index} aliases an earlier scratch lane"
        );
        assert!(
            src.iter().all(|other| other.id() != lane.id()),
            "fused zero-prefix increment scratch lane {index} aliases the source"
        );
        assert!(
            target.iter().all(|other| other.id() != lane.id()),
            "fused zero-prefix increment scratch lane {index} aliases the target"
        );
    }
    if let Some(scratch) = full_scratch {
        if scratch.len() == DIRECT_PREFIX_COMPACT7_SCRATCH_LEN {
            assert!(!dirty_updates && !no_materialized_flag);
            assert_eq!(
                omitted_high_bits, 5,
                "compact7 direct-prefix scratch is sealed to split-five bit length"
            );
            assert!(
                crate::point_add::trailmix_port::arith::khattar_gidney::kg_prefix_ancilla_count(
                    target.len(),
                ) + 1
                    <= scratch.len() - DIRECT_PREFIX_KG_SCRATCH_LEN,
                "compact7 direct-prefix scratch needs room for exact increment ancillae and one flag"
            );
            assert_direct_prefix_compact7_scratch(src, target, scratch);
        } else if scratch.len() == DIRECT_PREFIX_COMPACT_SCRATCH_LEN {
            assert!(!dirty_updates && !no_materialized_flag);
            assert!(
                crate::point_add::trailmix_port::arith::khattar_gidney::kg_prefix_ancilla_count(
                    target.len(),
                ) + 1
                    <= DIRECT_PREFIX_INCREMENT_SCRATCH_LEN,
                "compact direct-prefix scratch needs room for exact increment ancillae and one flag"
            );
            assert_direct_prefix_compact_scratch(src, target, scratch);
        } else {
            assert_direct_prefix_full_scratch(src, target, scratch);
        }
    }
}

/// Add or subtract `bitlen(src)` without materializing the MSB position.
///
/// Let `z_i(src) = product_{j=n-i}^{n-1}(1-src_j)`. The prefix-AND traversal
/// over the complemented, MSB-first source exposes `z_i` at callback `i`, so
///
///     bitlen(src) = n - sum_{i=1}^n z_i(src).
///
/// The `i=n` term is enabled only by `LOWQ_FUSED_ZERO_PREFIX_BITLEN`; without
/// it the historical nonzero-source traversal is preserved. We first
/// add/subtract the classical constant `n`, then apply the opposite unit update
/// for every selected all-zero prefix. This removes the ten-qubit position
/// register and its variable add. The prefix producer still uses only
/// `log*(n)` clean ancillae; each unit update is on the ten-bit length target,
/// so the extra Toffoli work is polynomial and bounded by O(n log n).
fn bit_length_lean_direct_prefix(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    dirty_updates: bool,
    no_materialized_flag: bool,
    increment_scratch: &[&QReg],
    full_scratch: Option<&[&QReg]>,
    source_is_complemented: bool,
    omitted_high_bits: usize,
) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::{
        cdec_khattar_gidney_refs_with_anc_exact_reverse,
        cinc_khattar_gidney_refs_with_anc, kg_prefix_ancilla_count, KgPrefixAnd,
    };
    use crate::point_add::trailmix_port::arith::ripple_add::{add_const, sub_const};

    let n = src.len();
    if n == 0 {
        return;
    }
    let fuse_zero_prefix = lowq_fused_zero_prefix_bitlen_requested();
    if source_is_complemented {
        assert!(
            fuse_zero_prefix,
            "pre-complemented bit length requires fused zero-prefix semantics"
        );
        assert!(
            n > 1,
            "pre-complemented bit length does not support the one-bit fast path"
        );
    }
    let reverse_caller_scratch_decrement = caller_scratch_kg_reverse_decrement_requested();
    if fuse_zero_prefix {
        assert_fused_zero_prefix_preconditions(
            src,
            s,
            dirty_updates,
            no_materialized_flag,
            increment_scratch,
            full_scratch,
            omitted_high_bits,
        );
    }
    debug_assert!(
        (n as u128) < (1u128 << (s.len() + omitted_high_bits)),
        "bit_length_lean_direct_prefix: target width {} too small for n={n}",
        s.len()
    );

    if let Some(scratch) = full_scratch {
        let compact7_scratch = scratch.len() == DIRECT_PREFIX_COMPACT7_SCRATCH_LEN;
        let compact_scratch = scratch.len() == DIRECT_PREFIX_COMPACT_SCRATCH_LEN;
        assert!(
            !dirty_updates,
            "direct-prefix caller scratch forbids dirty updates"
        );
        assert!(
            !no_materialized_flag,
            "direct-prefix caller scratch requires a materialized flag"
        );
        if compact7_scratch {
            assert_eq!(
                omitted_high_bits, 5,
                "compact7 direct-prefix scratch is sealed to split-five bit length"
            );
            assert!(
                kg_prefix_ancilla_count(s.len()) + 1
                    <= scratch.len() - DIRECT_PREFIX_KG_SCRATCH_LEN,
                "compact7 direct-prefix scratch needs room for exact increment ancillae and one flag"
            );
            assert_direct_prefix_compact7_scratch(src, s, scratch);
        } else if compact_scratch {
            assert!(
                kg_prefix_ancilla_count(s.len()) + 1
                    <= DIRECT_PREFIX_INCREMENT_SCRATCH_LEN,
                "compact direct-prefix scratch needs room for exact increment ancillae and one flag"
            );
            assert_direct_prefix_compact_scratch(src, s, scratch);
        } else {
            assert_direct_prefix_full_scratch(src, s, scratch);
        }
        assert!(
            increment_scratch.is_empty(),
            "direct-prefix full scratch cannot be combined with increment-only scratch"
        );
        assert!(
            kg_prefix_ancilla_count(n) <= DIRECT_PREFIX_KG_SCRATCH_LEN,
            "direct-prefix source width {n} exceeds the five-lane KG scratch budget"
        );
        assert!(
            kg_prefix_ancilla_count(s.len()) <= DIRECT_PREFIX_INCREMENT_SCRATCH_LEN,
            "direct-prefix target width {} exceeds the three-lane increment scratch budget",
            s.len()
        );
    }

    let full_increment_scratch = full_scratch.map(|scratch| {
        let count = kg_prefix_ancilla_count(s.len());
        &scratch[DIRECT_PREFIX_KG_SCRATCH_LEN..DIRECT_PREFIX_KG_SCRATCH_LEN + count]
    });
    let borrowed_flag = full_scratch.map(|scratch| {
        let index = if scratch.len() == DIRECT_PREFIX_FULL_SCRATCH_LEN {
            DIRECT_PREFIX_FULL_SCRATCH_LEN - 1
        } else if scratch.len() == DIRECT_PREFIX_COMPACT7_SCRATCH_LEN {
            DIRECT_PREFIX_COMPACT7_SCRATCH_LEN - 1
        } else {
            assert_eq!(scratch.len(), DIRECT_PREFIX_COMPACT_SCRATCH_LEN);
            DIRECT_PREFIX_COMPACT_SCRATCH_LEN - 1
        };
        assert!(
            DIRECT_PREFIX_KG_SCRATCH_LEN + kg_prefix_ancilla_count(s.len()) <= index
        );
        scratch[index]
    });
    if fuse_zero_prefix && n == 1 {
        // bitlen(x_0) = 1 - (1 - x_0) = x_0.  Avoid emitting the general
        // constant-plus-prefix decomposition for this exact base case.
        let control = src[0];
        let sref: Vec<&QReg> = s.iter().collect();
        let scratch = full_increment_scratch.unwrap_or(increment_scratch);
        if scratch.len() >= kg_prefix_ancilla_count(sref.len()) {
            if dec {
                for lane in &sref {
                    circ.x(lane);
                }
            }
            cinc_khattar_gidney_refs_with_anc(circ, &sref, control, scratch);
            if dec {
                for lane in &sref {
                    circ.x(lane);
                }
            }
        } else if dec {
            ctrl_dec_refs(circ, control, &sref);
        } else {
            ctrl_inc_refs(circ, control, &sref);
        }
        return;
    }
    if let (Some(control), Some(constant_scratch)) = (borrowed_flag, full_increment_scratch) {
        // n = sum_i n_i 2^i. Add each set term by incrementing s[i..]. The
        // default decrement uses x - 1 = NOT(NOT(x) + 1); the opt-in route
        // emits the literal reverse CINC stream instead. The borrowed flag is
        // temporarily |1>, and the same three clean increment lanes used by
        // the prefix callbacks keep this fixed-constant update allocation-free.
        let s_refs: Vec<&QReg> = s.iter().collect();
        circ.x(control);
        for bit in 0..s.len() {
            if ((n >> bit) & 1) == 0 {
                continue;
            }
            let suffix = &s_refs[bit..];
            if dec && reverse_caller_scratch_decrement {
                cdec_khattar_gidney_refs_with_anc_exact_reverse(
                    circ,
                    suffix,
                    control,
                    constant_scratch,
                );
            } else {
                if dec {
                    for lane in suffix {
                        circ.x(lane);
                    }
                }
                cinc_khattar_gidney_refs_with_anc(circ, suffix, control, constant_scratch);
                if dec {
                    for lane in suffix {
                        circ.x(lane);
                    }
                }
            }
        }
        circ.x(control);
    } else {
        let n_bytes = n.to_le_bytes();
        if dec {
            sub_const(circ, s, &n_bytes);
        } else {
            add_const(circ, s, &n_bytes);
        }
    }
    let prefix_allocation_serial = full_scratch.map(|_| circ.b.allocation_serial);

    if !source_is_complemented {
        for q in src {
            circ.x(q);
        }
    }
    let qbits: Vec<&QReg> = src.iter().rev().copied().collect();
    let anc_owned = if full_scratch.is_some() {
        Vec::new()
    } else {
        circ.alloc_qreg_bits(
            "bll.direct-prefix.kganc",
            kg_prefix_ancilla_count(n),
        )
    };
    let anc: Vec<&QReg> = full_scratch.map_or_else(
        || anc_owned.iter().collect(),
        |scratch| scratch[..DIRECT_PREFIX_KG_SCRATCH_LEN].to_vec(),
    );
    let increment_scratch = full_increment_scratch.unwrap_or(increment_scratch);
    let sref: Vec<&QReg> = s.iter().collect();
    let dirty_candidates: Vec<&QReg> = qbits
        .iter()
        .copied()
        .chain(anc.iter().copied())
        .collect();
    let direct_double_control = dirty_updates
        && no_materialized_flag
        && dirty_candidates.len().saturating_sub(2) >= sref.len().saturating_sub(1);
    let flag_owned = if direct_double_control || borrowed_flag.is_some() {
        None
    } else {
        Some(circ.alloc_qreg("bll.direct-prefix.flag"))
    };
    let flag = if direct_double_control {
        None
    } else {
        borrowed_flag.or(flag_owned.as_ref())
    };

    let done = KgPrefixAnd::new(&qbits, &anc).forward(circ, |c, i, controls| {
        // i=0 is the empty prefix already accounted for by the constant n.
        // Historically i=n was omitted and repaired by a separate zero flag.
        if i == 0 || i > n || (i == n && !fuse_zero_prefix) {
            return;
        }
        let update = |c: &mut Circuit, control: &QReg| {
            let dirty_available = dirty_candidates
                .iter()
                .filter(|candidate| candidate.id() != control.id())
                .count();
            if dirty_updates && dirty_available >= sref.len().saturating_sub(2) {
                dirty_controlled_inc_suffix(
                    c,
                    &[control],
                    &sref,
                    0,
                    !dec,
                    &dirty_candidates,
                );
            } else if increment_scratch.len() >= kg_prefix_ancilla_count(sref.len()) {
                if dec {
                    cinc_khattar_gidney_refs_with_anc(c, &sref, control, increment_scratch);
                } else if reverse_caller_scratch_decrement {
                    cdec_khattar_gidney_refs_with_anc_exact_reverse(
                        c,
                        &sref,
                        control,
                        increment_scratch,
                    );
                } else {
                    for q in &sref {
                        c.x(q);
                    }
                    cinc_khattar_gidney_refs_with_anc(c, &sref, control, increment_scratch);
                    for q in &sref {
                        c.x(q);
                    }
                }
            } else if dec {
                ctrl_inc_refs(c, control, &sref);
            } else {
                ctrl_dec_refs(c, control, &sref);
            }
        };
        match controls {
            [control] => update(c, control),
            [a, b] => {
                if direct_double_control {
                    dirty_controlled_inc_suffix(
                        c,
                        &[a, b],
                        &sref,
                        0,
                        !dec,
                        &dirty_candidates,
                    );
                } else {
                    let flag = flag.expect("materialized prefix flag");
                    c.ccx(a, b, flag);
                    update(c, flag);
                    c.clear_and(flag, a, b);
                }
            }
            _ => unreachable!("KG prefix controls must contain one or two qubits"),
        }
    });
    done.reverse(circ, |_, _, _| {});

    if let Some(flag) = flag_owned {
        circ.zero_and_free(flag);
    }
    drop(anc);
    for q in anc_owned {
        circ.zero_and_free(q);
    }
    if !source_is_complemented {
        for q in src {
            circ.x(q);
        }
    }
    if let Some(allocation_serial) = prefix_allocation_serial {
        assert_eq!(
            circ.b.allocation_serial, allocation_serial,
            "caller-supplied direct-prefix traversal allocated an internal qubit"
        );
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct DirectPrefixBitLengthProofReport {
    pub cases_checked: usize,
    pub directions_checked: usize,
    pub maximum_extra_qubits: usize,
    pub maximum_emitted_ops: usize,
    pub maximum_emitted_toffoli: usize,
}

/// Exhaustively verify the direct-prefix update for every nonzero eight-bit
/// source, every five-bit accumulator value, and both add/subtract directions.
/// This is a production-build diagnostic because the inherited crate-wide test
/// target currently contains unrelated stale tests and missing dev dependencies.
#[doc(hidden)]
fn direct_prefix_bit_length_roundtrip_check_mode(
    dirty_updates: bool,
    no_materialized_flag: bool,
) -> DirectPrefixBitLengthProofReport {
    use crate::circuit::{OperationType, QubitId};
    use crate::sim::Simulator;
    use sha3::{
        digest::{ExtendableOutput, Update},
        Shake128,
    };

    let mut cases_checked = 0usize;
    let mut maximum_extra_qubits = 0usize;
    let mut maximum_emitted_ops = 0usize;
    let mut maximum_emitted_toffoli = 0usize;

    for dec in [false, true] {
        let mut circuit = Circuit::new();
        let source = circuit.alloc_qreg_bits("direct-bitlen-proof.source", 8);
        let target = circuit.alloc_qreg_bits("direct-bitlen-proof.target", 5);
        let source_refs: Vec<&QReg> = source.iter().collect();
        bit_length_lean_direct_prefix(
            &mut circuit,
            &source_refs,
            &target,
            dec,
            dirty_updates,
            no_materialized_flag,
            &[],
            None,
            false,
            0,
        );

        let source_ids: Vec<u32> = source.iter().map(QReg::id).collect();
        let target_ids: Vec<u32> = target.iter().map(QReg::id).collect();
        let external: Vec<u32> = source_ids
            .iter()
            .chain(target_ids.iter())
            .copied()
            .collect();
        let builder = circuit.into_builder();
        maximum_extra_qubits = maximum_extra_qubits
            .max(builder.peak_qubits as usize - external.len());
        maximum_emitted_ops = maximum_emitted_ops.max(builder.ops.len());
        maximum_emitted_toffoli = maximum_emitted_toffoli.max(
            builder
                .ops
                .iter()
                .filter(|op| matches!(op.kind, OperationType::CCX | OperationType::CCZ))
                .count(),
        );

        let cases: Vec<(u64, u64)> = (1u64..=255)
            .flat_map(|source_value| {
                (0u64..32).map(move |target_value| (source_value, target_value))
            })
            .collect();
        for (batch, chunk) in cases.chunks(64).enumerate() {
            let mut seed = Shake128::default();
            seed.update(if dec {
                b"direct-prefix-bitlen-sub"
            } else {
                b"direct-prefix-bitlen-add"
            });
            seed.update(&(batch as u64).to_le_bytes());
            let mut xof = seed.finalize_xof();
            let mut simulator = Simulator::new(
                builder.next_qubit as usize,
                builder.next_bit as usize,
                &mut xof,
            );
            for (shot, &(source_value, target_value)) in chunk.iter().enumerate() {
                for (bit, &id) in source_ids.iter().enumerate() {
                    if (source_value >> bit) & 1 == 1 {
                        *simulator.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
                    }
                }
                for (bit, &id) in target_ids.iter().enumerate() {
                    if (target_value >> bit) & 1 == 1 {
                        *simulator.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
                    }
                }
            }
            simulator.apply_iter(builder.ops.iter());
            let live = if chunk.len() == 64 {
                u64::MAX
            } else {
                (1u64 << chunk.len()) - 1
            };
            assert_eq!(
                simulator.phase & live,
                0,
                "direct prefix update left phase garbage in batch {batch}"
            );

            for (shot, &(source_value, target_value)) in chunk.iter().enumerate() {
                let bit_length = 64 - source_value.leading_zeros() as u64;
                let expected = if dec {
                    target_value.wrapping_sub(bit_length) & 31
                } else {
                    target_value.wrapping_add(bit_length) & 31
                };
                let read = |ids: &[u32]| {
                    ids.iter().enumerate().fold(0u64, |value, (bit, &id)| {
                        value
                            | (((simulator.qubit(QubitId(u64::from(id))) >> shot) & 1) << bit)
                    })
                };
                assert_eq!(
                    read(&source_ids),
                    source_value,
                    "source changed in batch {batch}, shot {shot}"
                );
                assert_eq!(
                    read(&target_ids),
                    expected,
                    "target mismatch in batch {batch}, shot {shot}"
                );
            }
            for id in 0..builder.next_qubit {
                if !external.contains(&id) {
                    assert_eq!(
                        simulator.qubit(QubitId(u64::from(id))) & live,
                        0,
                        "direct prefix update left internal q{id} dirty in batch {batch}"
                    );
                }
            }
            cases_checked += chunk.len();
        }
    }

    DirectPrefixBitLengthProofReport {
        cases_checked,
        directions_checked: 2,
        maximum_extra_qubits,
        maximum_emitted_ops,
        maximum_emitted_toffoli,
    }
}

#[doc(hidden)]
pub fn direct_prefix_bit_length_roundtrip_check() -> DirectPrefixBitLengthProofReport {
    direct_prefix_bit_length_roundtrip_check_mode(false, false)
}

#[doc(hidden)]
pub fn direct_prefix_dirty_bit_length_roundtrip_check() -> DirectPrefixBitLengthProofReport {
    direct_prefix_bit_length_roundtrip_check_mode(true, false)
}

#[doc(hidden)]
pub fn direct_prefix_no_flag_bit_length_roundtrip_check() -> DirectPrefixBitLengthProofReport {
    direct_prefix_bit_length_roundtrip_check_mode(true, true)
}

/// `s += bitlen(src)` (or `-=` if dec). Built from [`bit_length_lean_middle`]:
/// pos = MSB index in the middle, then `s ±= (pos + 1)`. With `dec` this clears a
/// register `s` that already holds `bitlen(src)` (the "same method" both ways).
#[derive(Clone, Copy)]
struct BitLengthCallsiteTrace {
    sections: [&'static str; 2],
    next: usize,
}

thread_local! {
    static BIT_LENGTH_CALLSITE_TRACE: std::cell::Cell<Option<BitLengthCallsiteTrace>> =
        const { std::cell::Cell::new(None) };
}

/// Relabel an existing bit-length compute/uncompute pair without adding a
/// section transition, allocation, or emitted operation.
pub(crate) fn with_bit_length_callsite<R>(
    deposit_section: &'static str,
    erase_section: &'static str,
    body: impl FnOnce() -> R,
) -> R {
    let previous = BIT_LENGTH_CALLSITE_TRACE.with(|trace| {
        trace.replace(Some(BitLengthCallsiteTrace {
            sections: [deposit_section, erase_section],
            next: 0,
        }))
    });
    assert!(previous.is_none(), "nested bit-length call-site tracing is unsupported");
    let result = body();
    let completed = BIT_LENGTH_CALLSITE_TRACE
        .with(|trace| trace.replace(previous))
        .expect("bit-length call-site trace disappeared");
    assert_eq!(
        completed.next, 2,
        "bit-length call-site trace expected one compute/uncompute pair"
    );
    result
}

fn bit_length_section() -> &'static str {
    BIT_LENGTH_CALLSITE_TRACE.with(|trace| {
        let Some(mut current) = trace.get() else {
            return "p.bitlen";
        };
        assert!(
            current.next < current.sections.len(),
            "bit-length call-site emitted more than one compute/uncompute pair"
        );
        let section = current.sections[current.next];
        current.next += 1;
        trace.set(Some(current));
        section
    })
}

fn bit_length_lean_impl(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    increment_scratch: &[&QReg],
    full_scratch: Option<&[&QReg]>,
    source_is_complemented: bool,
    omitted_high_bits: usize,
) {
    let n = src.len();
    if n == 0 {
        return;
    }
    let pbl = circ.push_section(bit_length_section());
    if lowq_direct_prefix_bitlen_requested() {
        bit_length_lean_direct_prefix(
            circ,
            src,
            s,
            dec,
            lowq_direct_prefix_dirty_update_requested(),
            lowq_direct_prefix_no_flag_requested(),
            increment_scratch,
            full_scratch,
            source_is_complemented,
            omitted_high_bits,
        );
        circ.pop_section(&pbl);
        return;
    }
    assert!(
        !source_is_complemented,
        "pre-complemented bit length requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    // pos holds transient gray values up to (n-1)^n < 2n; reuse s's width (equal-
    // width so the Cuccaro add s += pos is clean).
    let pos_w = s.len();
    debug_assert!(
        (n as u64) <= (1u64 << (pos_w - 1)),
        "bit_length_lean: s width {pos_w} too small for n={n}"
    );
    let pos = circ.alloc_qreg_bits("bll.pos", pos_w);
    xor_const(circ, &pos, n); // pos = n  (PRE for the middle)
    bit_length_lean_middle(circ, src, &pos, |circ| {
        // pos = MSB index = bitlen-1; s ±= (pos + 1).
        if dec {
            for q in s {
                circ.x(q);
            }
        }
        let pref: Vec<&QReg> = pos.iter().collect();
        let sref: Vec<&QReg> = s.iter().collect();
        add_refs(circ, &sref, &pref); // s += pos
        let one = circ.alloc_qreg("bll.one");
        circ.x(&one);
        ctrl_inc(circ, &one, s); // s += 1  (bitlen = p + 1)
        circ.x(&one);
        circ.zero_and_free(one);
        if dec {
            for q in s {
                circ.x(q);
            }
        }
        true // pos is a throwaway temp -> clean on reverse (4n)
    });
    xor_const(circ, &pos, n); // pos back to |0>
    for q in pos {
        circ.zero_and_free(q);
    }
    circ.pop_section(&pbl);
}

pub(crate) fn bit_length_lean(circ: &mut Circuit, src: &[&QReg], s: &[QReg], dec: bool) {
    bit_length_lean_impl(circ, src, s, dec, &[], None, false, 0);
}

/// Apply the direct-prefix bit-length update while `src` is already bitwise
/// complemented. The source remains complemented on return.
pub(crate) fn bit_length_lean_complemented_source(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
) {
    bit_length_lean_impl(circ, src, s, dec, &[], None, true, 0);
}

pub(crate) fn bit_length_lean_with_increment_scratch(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    increment_scratch: &[&QReg],
) {
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        increment_scratch,
        None,
        false,
        0,
    );
}

pub(crate) fn bit_length_lean_with_full_prefix_scratch(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "full direct-prefix scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        false,
        0,
    );
}

/// Full-scratch variant of [`bit_length_lean_complemented_source`].
pub(crate) fn bit_length_lean_with_full_prefix_scratch_complemented_source(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "full direct-prefix scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        true,
        0,
    );
}

/// Compute the low bits of `bitlen(src)` modulo `2^s.len()`. The caller
/// separately owns and restores the single omitted high bit.
pub(crate) fn bit_length_lean_with_full_prefix_scratch_split_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-high full scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        source_is_complemented,
        1,
    );
}

/// Compute the low bits of `bitlen(src)` while the caller separately owns and
/// restores two omitted high bits.
pub(crate) fn bit_length_lean_with_full_prefix_scratch_split_two_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-two-high full scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        source_is_complemented,
        2,
    );
}

/// Compute the six low bits of `bitlen(src)` while the caller separately owns
/// and restores the three omitted high bits.
pub(crate) fn bit_length_lean_with_full_prefix_scratch_split_three_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-three-high full scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        source_is_complemented,
        3,
    );
}

/// Compute the five low bits of `bitlen(src)` while the caller separately
/// owns and restores the four omitted high bits.
pub(crate) fn bit_length_lean_with_full_prefix_scratch_split_four_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-four-high full scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        source_is_complemented,
        4,
    );
}

/// Compute the four low bits of `bitlen(src)` while the caller separately
/// owns and restores the five omitted high bits.
pub(crate) fn bit_length_lean_with_full_prefix_scratch_split_five_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-five-high full scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    bit_length_lean_impl(
        circ,
        src,
        s,
        dec,
        &[],
        Some(full_scratch),
        source_is_complemented,
        5,
    );
}

/// Eight-lane split-five variant used by the Q825 direct-metadata route. A
/// four-bit accumulator needs one increment ancilla, so the last lane of the
/// generic three-lane increment budget can host the materialized prefix flag.
pub(crate) fn bit_length_lean_with_compact_prefix_scratch_split_five_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-five-high compact scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    assert_eq!(full_scratch.len(), DIRECT_PREFIX_COMPACT_SCRATCH_LEN);
    let section = circ.push_section(bit_length_section());
    bit_length_lean_direct_prefix(
        circ,
        src,
        s,
        dec,
        false,
        false,
        &[],
        Some(full_scratch),
        source_is_complemented,
        5,
    );
    circ.pop_section(&section);
}

/// Seven-lane split-five variant used when the caller's four-bit length target
/// needs only one increment ancilla and a materialized prefix flag.
pub(crate) fn bit_length_lean_with_compact7_prefix_scratch_split_five_high(
    circ: &mut Circuit,
    src: &[&QReg],
    s: &[QReg],
    dec: bool,
    full_scratch: &[&QReg],
    source_is_complemented: bool,
) {
    assert!(
        lowq_direct_prefix_bitlen_requested(),
        "split-five-high compact7 scratch requires LOWQ_DIRECT_PREFIX_BITLEN=1"
    );
    assert_eq!(full_scratch.len(), DIRECT_PREFIX_COMPACT7_SCRATCH_LEN);
    assert_eq!(s.len(), 4);
    let section = circ.push_section(bit_length_section());
    bit_length_lean_direct_prefix(
        circ,
        src,
        s,
        dec,
        false,
        false,
        &[],
        Some(full_scratch),
        source_is_complemented,
        5,
    );
    circ.pop_section(&section);
}

fn lowq_clz_diff_const_fold_enabled() -> bool {
    if std::env::var("LOWQ_CLZ_DIFF_CONST_FOLD").ok().as_deref() != Some("1") {
        return false;
    }
    let target = std::env::var("TRAILMIX_Q_TARGET")
        .ok()
        .and_then(|value| value.parse::<usize>().ok())
        .expect("LOWQ_CLZ_DIFF_CONST_FOLD requires an integer TRAILMIX_Q_TARGET");
    assert!(
        matches!(target, 683 | 684 | 685),
        "LOWQ_CLZ_DIFF_CONST_FOLD repair audit permits Q_TARGET 683/684/685"
    );
    true
}

fn lowq_hybrid_clz_enabled() -> bool {
    if std::env::var("LOWQ_HYBRID_CLZ").ok().as_deref() != Some("1") {
        return false;
    }
    assert_eq!(
        trailmix_logical_srot_width(),
        5,
        "LOWQ_HYBRID_CLZ requires the five-bit shift register"
    );
    assert_eq!(
        env_usize("TRAILMIX_THIN_CLZ_WINDOW", 0),
        78,
        "LOWQ_HYBRID_CLZ is sealed to the audited 78-bit windows"
    );
    assert!(
        matches!(env_usize("TRAILMIX_Q_TARGET", 0), 683 | 684 | 685),
        "LOWQ_HYBRID_CLZ repair audit permits Q_TARGET 683/684/685"
    );
    true
}

fn lowq_exact_ctz_enabled() -> bool {
    if std::env::var("LOWQ_EXACT_CTZ").ok().as_deref() != Some("1") {
        return false;
    }
    assert_eq!(
        trailmix_logical_srot_width(),
        5,
        "LOWQ_EXACT_CTZ requires the five-bit shift register"
    );
    assert!(
        matches!(env_usize("TRAILMIX_Q_TARGET", 0), 683 | 684 | 685),
        "LOWQ_EXACT_CTZ repair audit permits Q_TARGET 683/684/685"
    );
    true
}

fn lowq_hybrid_clz_kg_mcx_enabled() -> bool {
    std::env::var("LOWQ_HYBRID_CLZ_KG_MCX").ok().as_deref() == Some("1")
}

fn lowq_hybrid_clz_prefix_parity_enabled() -> bool {
    std::env::var("LOWQ_HYBRID_CLZ_PREFIX_PARITY").ok().as_deref() == Some("1")
}

fn lowq_hybrid_clz_noalloc_add_enabled() -> bool {
    std::env::var("LOWQ_HYBRID_CLZ_NOALLOC_ADD").ok().as_deref() == Some("1")
}

fn lowq_q948_direct_hclz_peak_guard_enabled() -> bool {
    if std::env::var("LOWQ_Q948_DIRECT_HCLZ_PEAK_GUARD")
        .ok()
        .as_deref()
        != Some("1")
    {
        return false;
    }
    assert_eq!(
        std::env::var("LOWQ_Q949_AFFINE_COUNTER").ok().as_deref(),
        Some("1"),
        "LOWQ_Q948_DIRECT_HCLZ_PEAK_GUARD requires the affine-counter route"
    );
    assert_eq!(
        std::env::var("LOWQ_Q949_ROBUST_SYMMETRIC_SCHEDULE")
            .ok()
            .as_deref(),
        Some("1"),
        "LOWQ_Q948_DIRECT_HCLZ_PEAK_GUARD requires the robust symmetric schedule"
    );
    let q947_route = q947_passenger_direct_hclz_requested();
    assert_eq!(
        std::env::var("LOWQ_PASSENGER_TOP_LIFETIME_EXPERIMENT")
            .ok()
            .as_deref(),
        Some(if q947_route { "1" } else { "0" }),
        "direct HCLZ passenger composition drift"
    );
    if q947_route {
        assert_eq!(
            std::env::var("LOWQ_BORROWED_TRANSCRIPT_EXPERIMENT")
                .ok()
                .as_deref(),
            Some("1"),
            "Q947 direct HCLZ requires the six-owned-plus-one-borrowed transcript"
        );
        assert_eq!(
            env_usize("TRAILMIX_Q_TARGET", 0),
            683,
            "Q947 direct HCLZ is sealed to Q_TARGET=683"
        );
    }
    assert_eq!(
        std::env::var("LOWQ_REVERSE_CA255_RELATIONAL_LOAN_EXPERIMENT")
            .ok()
            .as_deref(),
        Some("0"),
        "LOWQ_Q948_DIRECT_HCLZ_PEAK_GUARD keeps the rejected ca[255] relation off"
    );
    true
}

fn lowq_q957_target683_enabled() -> bool {
    std::env::var("LOWQ_Q957_TARGET683").ok().as_deref() == Some("1")
}

fn lowq_q959_selective_borrow_enabled() -> bool {
    if std::env::var("LOWQ_Q959_SELECTIVE_BORROW").ok().as_deref() != Some("1") {
        return false;
    }
    assert_eq!(
        trailmix_logical_srot_width(),
        5,
        "LOWQ_Q959_SELECTIVE_BORROW requires five shift lanes"
    );
    assert_eq!(
        env_usize("TRAILMIX_THIN_CLZ_WINDOW", 0),
        78,
        "LOWQ_Q959_SELECTIVE_BORROW is sealed to the 78-bit schedule"
    );
    let q_target = env_usize("TRAILMIX_Q_TARGET", 0);
    assert!(
        q_target == 684 || (q_target == 683 && lowq_q957_target683_enabled()),
        "LOWQ_Q959_SELECTIVE_BORROW requires Q_TARGET=684 or the Q957 target683 route"
    );
    assert_eq!(
        std::env::var("TRAILMIX_SIGN_PARITY_Q_REUSE").ok().as_deref(),
        Some("1"),
        "LOWQ_Q959_SELECTIVE_BORROW requires sign/parity fusion"
    );
    assert_eq!(
        std::env::var("LOWQ_EXACT_CTZ").ok().as_deref(),
        Some("1"),
        "LOWQ_Q959_SELECTIVE_BORROW requires exact in-place CTZ"
    );
    true
}

fn lowq_q958_gated_compare_enabled() -> bool {
    if std::env::var("LOWQ_Q958_GATED_COMPARE").ok().as_deref() != Some("1") {
        return false;
    }
    assert!(
        lowq_q959_selective_borrow_enabled(),
        "LOWQ_Q958_GATED_COMPARE requires the sealed selective-borrow route"
    );
    true
}

fn lowq_q956_off_borrow_enabled() -> bool {
    if std::env::var("LOWQ_Q956_OFF_BORROW").ok().as_deref() != Some("1") {
        return false;
    }
    assert!(
        lowq_q958_gated_compare_enabled(),
        "LOWQ_Q956_OFF_BORROW requires the sealed Q958 gated-comparator route"
    );
    assert!(
        lowq_q957_target683_enabled(),
        "LOWQ_Q956_OFF_BORROW requires the Q957 target683 route"
    );
    let q946_route = q946_second_ownership_release_requested();
    if q947_passenger_direct_hclz_requested() {
        assert!(
            q946_route,
            "Q947 direct-HCLZ may borrow off only through the Q946 ownership route"
        );
    }
    if q946_route {
        assert!(
            q947_passenger_direct_hclz_requested() && q949_affine_counter_requested(),
            "Q946 second ownership release requires the Q947 affine route"
        );
    }
    assert_eq!(
        env_usize("TRAILMIX_Q_TARGET", 0),
        683,
        "LOWQ_Q956_OFF_BORROW is sealed to Q_TARGET=683"
    );
    assert_eq!(
        env_usize("TRAILMIX_Q_CAP", 0),
        99,
        "LOWQ_Q956_OFF_BORROW is sealed to Q_CAP=99"
    );
    assert_eq!(
        env_usize("TRAILMIX_COUNTER_W", 0),
        8,
        "LOWQ_Q956_OFF_BORROW is sealed to the eight-bit counter"
    );
    assert_eq!(
        trailmix_logical_srot_width(),
        5,
        "LOWQ_Q956_OFF_BORROW requires five logical arithmetic shift lanes"
    );
    assert!(
        std::env::var_os("TRAILMIX_PASSENGER_TOP_Q_REUSE").is_none(),
        "LOWQ_Q956_OFF_BORROW forbids passenger-top reuse"
    );
    true
}

fn lowq_q949_affine_counter_enabled() -> bool {
    if !q949_affine_counter_requested() {
        return false;
    }
    assert!(
        lowq_q958_gated_compare_enabled() && lowq_q957_target683_enabled(),
        "LOWQ_Q949_AFFINE_COUNTER requires the sealed target683 comparator route"
    );
    assert_eq!(
        env_usize("TRAILMIX_Q_TARGET", 0),
        683,
        "LOWQ_Q949_AFFINE_COUNTER is sealed to Q_TARGET=683"
    );
    assert_eq!(
        env_usize("TRAILMIX_Q_CAP", 0),
        99,
        "LOWQ_Q949_AFFINE_COUNTER preserves Q_CAP=99"
    );
    assert_eq!(
        env_usize("TRAILMIX_COUNTER_W", 0),
        8,
        "LOWQ_Q949_AFFINE_COUNTER requires an eight-bit logical terminal count"
    );
    assert_eq!(
        trailmix_srot_width(),
        5,
        "LOWQ_Q949_AFFINE_COUNTER requires five owned shift lanes"
    );
    assert!(
        !q954_srot_counter7_requested()
            && std::env::var("LOWQ_Q953_SROT_COUNTER67").ok().as_deref() != Some("1"),
        "LOWQ_Q949_AFFINE_COUNTER forbids Q954/Q953 counter aliases"
    );
    let q946_route = q946_second_ownership_release_requested();
    assert_eq!(
        std::env::var("LOWQ_Q956_OFF_BORROW").ok().as_deref(),
        Some(if q946_route { "1" } else { "0" }),
        "LOWQ_Q949_AFFINE_COUNTER requires dedicated off outside the Q946 ownership route"
    );
    assert_eq!(
        std::env::var("LOWQ_Q955_OFF_CANONICAL").ok().as_deref(),
        Some("1"),
        "LOWQ_Q949_AFFINE_COUNTER preserves the Q955 canonical cleanup"
    );
    assert!(
        std::env::var_os("TRAILMIX_PASSENGER_TOP_Q_REUSE").is_none(),
        "LOWQ_Q949_AFFINE_COUNTER forbids passenger-top reuse"
    );
    assert!(
        std::env::var_os("TRAILMIX_Q_MODEL_GUARD").is_none(),
        "LOWQ_Q949_AFFINE_COUNTER forbids TRAILMIX_Q_MODEL_GUARD"
    );
    assert!(
        std::env::var_os("TRAILMIX_AB_CAP").is_none()
            && std::env::var_os("TRAILMIX_CACB_CAP").is_none(),
        "LOWQ_Q949_AFFINE_COUNTER forbids unproved register caps"
    );
    let proof_mode = std::env::var("LOWQ_Q949_PROOF_MODE").ok().as_deref() == Some("1");
    let support_certified = if q949_robust_symmetric_schedule_requested() {
        std::env::var("LOWQ_Q949_ROBUST_FRESH_SUPPORT_CERTIFIED")
            .ok()
            .as_deref()
            == Some("1")
    } else {
        std::env::var("LOWQ_Q949_TERMINAL_SUPPORT_CERTIFIED")
            .ok()
            .as_deref()
            == Some("1")
    };
    assert!(
        proof_mode || support_certified,
        "LOWQ_Q949_AFFINE_COUNTER is fail-closed without proof mode or its route-specific support certificate"
    );
    let schedule = q954_srot_counter7_schedule_certificate();
    assert_eq!(schedule.first_terminal_capable_row, Q949_FIRST_TERMINAL_ROW);
    assert_eq!(schedule.max_final_counter, 159);
    true
}

/// Borrowed-transcript route. Discovery and census run in proof mode; a
/// certificate-gated profile additionally requires its own fresh-support
/// authorization because the parent robust certificate covers a different
/// committed operation stream.
fn lowq_borrowed_transcript_experiment_enabled() -> bool {
    if !borrowed_transcript_experiment_requested() {
        return false;
    }
    assert!(
        lowq_q949_affine_counter_enabled() && q949_robust_symmetric_schedule_requested(),
        "borrowed transcript requires the robust affine route"
    );
    let proof_mode = std::env::var("LOWQ_Q949_PROOF_MODE").ok().as_deref() == Some("1");
    let borrowed_fresh = std::env::var("LOWQ_BORROWED_TRANSCRIPT_FRESH_SUPPORT_CERTIFIED")
        .ok()
        .as_deref()
        == Some("1");
    assert!(
        proof_mode ^ borrowed_fresh,
        "borrowed transcript requires exactly one of proof mode or its route-specific fresh certificate"
    );
    let parent_fresh = std::env::var("LOWQ_Q949_ROBUST_FRESH_SUPPORT_CERTIFIED")
        .ok()
        .as_deref()
        == Some("1");
    assert_eq!(
        parent_fresh, borrowed_fresh,
        "borrowed-transcript profile requires both parent-envelope and route-specific fresh certificates"
    );
    true
}

/// Rejected reverse row-380 relational lender. WMI job 71373 found a fresh
/// trace with `ca[255]=0` while `active AND ca<cb=0`, falsifying the proposed
/// complement relation before width/CLZ support validation.
fn lowq_reverse_ca255_relational_loan_enabled() -> bool {
    if !reverse_ca255_relational_loan_requested() {
        return false;
    }
    panic!(
        "reverse ca[255] relational loan rejected by fresh WMI job 71373; \
         keep LOWQ_REVERSE_CA255_RELATIONAL_LOAN_EXPERIMENT=0"
    )
}

/// Passenger lifetime differential. The standalone experiment is structural
/// only; the composed Q947 route additionally admits its own fresh certificate.
fn lowq_passenger_top_lifetime_experiment_enabled() -> bool {
    if !passenger_top_lifetime_experiment_requested() {
        return false;
    }
    assert!(
        lowq_q949_affine_counter_enabled() && q949_robust_symmetric_schedule_requested(),
        "passenger lifetime requires the robust affine route"
    );
    assert!(
        !q954_srot_counter7_requested(),
        "passenger lifetime does not compose with the alternate srot route"
    );
    assert_eq!(
        std::env::var("LOWQ_Q955_OFF_CANONICAL").ok().as_deref(),
        Some("1"),
        "passenger lifetime requires canonical field arithmetic"
    );
    let proof_mode = std::env::var("LOWQ_Q949_PROOF_MODE").ok().as_deref() == Some("1");
    let q947_route = q947_passenger_direct_hclz_requested();
    let q947_fresh = std::env::var("LOWQ_Q947_FRESH_SUPPORT_CERTIFIED")
        .ok()
        .as_deref()
        == Some("1");
    if q947_route {
        let q946_route = q946_second_ownership_release_requested();
        assert_eq!(
            std::env::var("LOWQ_Q956_OFF_BORROW").ok().as_deref(),
            Some(if q946_route { "1" } else { "0" }),
            "Q947 off ownership drift"
        );
        assert_eq!(
            std::env::var("LOWQ_Q948_DIRECT_HCLZ_PEAK_GUARD")
                .ok()
                .as_deref(),
            Some("1"),
            "Q947 passenger release requires direct HCLZ"
        );
        assert_eq!(
            std::env::var("LOWQ_BORROWED_TRANSCRIPT_EXPERIMENT")
                .ok()
                .as_deref(),
            Some("1"),
            "Q947 passenger release requires borrowed transcript"
        );
        assert!(
            proof_mode ^ q947_fresh,
            "Q947 passenger release requires exactly one of proof mode or its fresh certificate"
        );
        let parent_fresh = std::env::var("LOWQ_Q949_ROBUST_FRESH_SUPPORT_CERTIFIED")
            .ok()
            .as_deref()
            == Some("1");
        let borrowed_fresh =
            std::env::var("LOWQ_BORROWED_TRANSCRIPT_FRESH_SUPPORT_CERTIFIED")
                .ok()
                .as_deref()
                == Some("1");
        assert!(
            parent_fresh == q947_fresh && borrowed_fresh == q947_fresh,
            "Q947 profile requires parent, borrowed-transcript, and Q947 certificates together"
        );
    } else {
        assert!(
            proof_mode && !q947_fresh,
            "standalone passenger lifetime is structural-only and requires proof mode"
        );
        assert_ne!(
            std::env::var("LOWQ_Q949_ROBUST_FRESH_SUPPORT_CERTIFIED")
                .ok()
                .as_deref(),
            Some("1"),
            "standalone passenger lifetime cannot inherit the parent certificate"
        );
    }
    true
}

fn lowq_q955_off_canonical_enabled() -> bool {
    if std::env::var("LOWQ_Q955_OFF_CANONICAL").ok().as_deref() != Some("1") {
        return false;
    }
    assert!(
        lowq_q956_off_borrow_enabled() || q949_affine_counter_requested(),
        "LOWQ_Q955_OFF_CANONICAL requires Q956 off-borrow or the Q949 affine route"
    );
    assert_eq!(
        env_usize("TRAILMIX_Q_TARGET", 0),
        683,
        "LOWQ_Q955_OFF_CANONICAL is sealed to Q_TARGET=683"
    );
    assert_eq!(
        env_usize("TRAILMIX_Q_CAP", 0),
        99,
        "LOWQ_Q955_OFF_CANONICAL preserves the Q_CAP=99 support widths"
    );
    assert_eq!(env_usize("TRAILMIX_COUNTER_W", 0), 8);
    assert!(
        std::env::var_os("TRAILMIX_PASSENGER_TOP_Q_REUSE").is_none(),
        "LOWQ_Q955_OFF_CANONICAL forbids passenger-top reuse"
    );
    assert!(
        std::env::var_os("TRAILMIX_Q_MODEL_GUARD").is_none(),
        "LOWQ_Q955_OFF_CANONICAL forbids TRAILMIX_Q_MODEL_GUARD"
    );
    true
}

const Q954_FIRST_TERMINAL_ROW: usize = 371;
const Q954_LAST_CTZ_BIT4_ROW: usize = 477;
const Q954_LAST_RAW_BIT4_BARREL_ROW: usize = 495;
const Q954_MAX_PRE_BODY_COUNTER: usize = 124;
const Q954_MAX_FINAL_COUNTER: usize = 159;
const Q954_SCHEDULE_FINGERPRINT: u64 = 0xf128_4a16_5e9c_235d;

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q954ScheduleCertificate {
    pub rows: usize,
    pub first_terminal_capable_row: usize,
    pub last_ctz_bit4_row: usize,
    pub last_raw_bit4_barrel_row: usize,
    pub max_pre_body_counter: usize,
    pub max_final_counter: usize,
    pub fingerprint: u64,
}

/// Bind the counter[7] alias proof to the exact generated 530-row schedule.
/// Terminal timing is authoritative support metadata; the raw barrel cutoff is
/// also re-derived from the checked shift-bound rows. Any schedule-array change
/// must be reviewed and issued a new fingerprint before this route can run.
#[doc(hidden)]
pub fn q954_srot_counter7_schedule_certificate() -> Q954ScheduleCertificate {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::{
        SHRUNKEN_PZ_A, SHRUNKEN_PZ_A_LO, SHRUNKEN_PZ_B, SHRUNKEN_PZ_B_LO,
        SHRUNKEN_PZ_CA, SHRUNKEN_PZ_CA_LO, SHRUNKEN_PZ_CB, SHRUNKEN_PZ_CB_LO,
        SHRUNKEN_PZ_NSTEPS, SHRUNKEN_PZ_Q, SHRUNKEN_PZ_Q_LO, SHRUNKEN_PZ_S2,
        SHRUNKEN_PZ_SDIV,
    };

    static CERTIFICATE: std::sync::OnceLock<Q954ScheduleCertificate> =
        std::sync::OnceLock::new();
    *CERTIFICATE.get_or_init(|| {
        fn mix(hash: &mut u64, value: u16) {
            for byte in value.to_le_bytes() {
                *hash ^= u64::from(byte);
                *hash = hash.wrapping_mul(0x100_0000_01b3);
            }
        }

        assert_eq!(SHRUNKEN_PZ_NSTEPS, 530, "Q954 schedule row-count drift");
        let mut fingerprint = 0xcbf2_9ce4_8422_2325u64;
        mix(&mut fingerprint, SHRUNKEN_PZ_NSTEPS as u16);
        for rows in [
            &SHRUNKEN_PZ_A,
            &SHRUNKEN_PZ_B,
            &SHRUNKEN_PZ_CA,
            &SHRUNKEN_PZ_CB,
            &SHRUNKEN_PZ_Q,
            &SHRUNKEN_PZ_A_LO,
            &SHRUNKEN_PZ_B_LO,
            &SHRUNKEN_PZ_CA_LO,
            &SHRUNKEN_PZ_CB_LO,
            &SHRUNKEN_PZ_Q_LO,
            &SHRUNKEN_PZ_SDIV,
            &SHRUNKEN_PZ_S2,
        ] {
            for &value in rows {
                mix(&mut fingerprint, value);
            }
        }
        assert_eq!(
            fingerprint, Q954_SCHEDULE_FINGERPRINT,
            "Q954 schedule fingerprint drift; reject counter[7] alias"
        );

        let last_raw_bit4_barrel_row = (0..SHRUNKEN_PZ_NSTEPS)
            .rev()
            .find(|&row| SHRUNKEN_PZ_SDIV[row] >= 16 || SHRUNKEN_PZ_S2[row] >= 16)
            .expect("Q954 schedule must exercise barrel bit4");
        assert_eq!(
            last_raw_bit4_barrel_row, Q954_LAST_RAW_BIT4_BARREL_ROW,
            "Q954 raw bit4 barrel cutoff drift"
        );
        assert_eq!(
            Q954_LAST_RAW_BIT4_BARREL_ROW - Q954_FIRST_TERMINAL_ROW,
            Q954_MAX_PRE_BODY_COUNTER,
            "Q954 pre-body counter bound drift"
        );
        assert_eq!(
            SHRUNKEN_PZ_NSTEPS - Q954_FIRST_TERMINAL_ROW,
            Q954_MAX_FINAL_COUNTER,
            "Q954 final counter bound drift"
        );
        assert!(
            Q954_MAX_PRE_BODY_COUNTER < (1 << 7),
            "Q954 counter[7] is not clean at the final bit4 barrel use"
        );
        assert!(
            Q954_MAX_FINAL_COUNTER < (1 << 8),
            "Q954 terminal counter exceeds its eight-bit register"
        );

        Q954ScheduleCertificate {
            rows: SHRUNKEN_PZ_NSTEPS,
            first_terminal_capable_row: Q954_FIRST_TERMINAL_ROW,
            last_ctz_bit4_row: Q954_LAST_CTZ_BIT4_ROW,
            last_raw_bit4_barrel_row,
            max_pre_body_counter: Q954_MAX_PRE_BODY_COUNTER,
            max_final_counter: Q954_MAX_FINAL_COUNTER,
            fingerprint,
        }
    })
}

fn lowq_q954_srot_counter7_enabled() -> bool {
    if !q954_srot_counter7_requested() {
        return false;
    }
    assert!(
        lowq_q955_off_canonical_enabled(),
        "LOWQ_Q954_SROT_COUNTER7 requires the composed Q955 canonical route"
    );
    assert_eq!(
        trailmix_srot_width(),
        4,
        "LOWQ_Q954_SROT_COUNTER7 allocates exactly four owned shift lanes"
    );
    assert_eq!(
        trailmix_counter_width(),
        8,
        "LOWQ_Q954_SROT_COUNTER7 requires counter[7]"
    );
    let certificate = q954_srot_counter7_schedule_certificate();
    assert_eq!(certificate.rows, 530);
    true
}

fn q954_ctz_width(row: usize) -> usize {
    if lowq_q954_srot_counter7_enabled() && row > Q954_LAST_CTZ_BIT4_ROW {
        4
    } else {
        5
    }
}

fn with_arithmetic_srot_view<'a, R>(
    owned: &'a [QReg],
    counter: &'a [QReg],
    body: impl FnOnce(&[&'a QReg]) -> R,
) -> R {
    if lowq_q954_srot_counter7_enabled() {
        assert_eq!(owned.len(), 4, "Q954 owned shift-lane count drift");
        assert_eq!(counter.len(), 8, "Q954 counter width drift");
        // This borrowed view exists only inside an already-gated arithmetic
        // body. The body is an exact cleanup block, so counter[7] is restored
        // before gate-holder or done logic evaluates the full counter again.
        let split = [
            &owned[0],
            &owned[1],
            &owned[2],
            &owned[3],
            &counter[7],
        ];
        body(&split)
    } else {
        let refs: Vec<&QReg> = owned.iter().collect();
        body(&refs)
    }
}

/// Undo the route-specific representation used to reconstruct a field product.
/// Q955 keeps every Horner state canonical; earlier routes retain the original
/// rfold representation and its matched cleanup.
pub(crate) fn shrunken_pz_product_undo(
    c: &mut Circuit,
    result: &[QReg],
    a: &[QReg],
    b: &[QReg],
) {
    if lowq_q955_off_canonical_enabled() {
        crate::point_add::trailmix_port::arith::rfold_mbu::mod_mul_canonical_mbu_undo(
            c, result, a, b,
        );
    } else {
        crate::point_add::trailmix_port::arith::rfold_mbu::mod_mul_rfold_mbu_undo(
            c, result, a, b,
        );
    }
}

fn assert_q956_off_alias(
    off: &QReg,
    counter: &[QReg],
    s_rot: &[QReg],
) {
    assert!(!counter.is_empty(), "Q956 off borrow requires a counter lane");
    assert!(
        std::ptr::eq(off, &counter[0]),
        "Q956 off must alias counter[0] exactly"
    );
    assert!(s_rot.len() >= 3, "Q956 boundary predicates require s_rot[0..3]");
    assert!(
        s_rot.iter().all(|lane| !std::ptr::eq(off, lane))
            && counter[1..].iter().all(|lane| !std::ptr::eq(off, lane)),
        "Q956 off alias overlaps a protected state lane"
    );
}

/// One controlled fixed-distance shift layer. The forward direction is a
/// logical left shift on the promised branch because its top `distance` lanes
/// are zero. Reversing the pair order is the exact inverse for arbitrary data.
fn controlled_fixed_shift(
    circ: &mut Circuit,
    reg: &[QReg],
    control: &QReg,
    distance: usize,
    forward: bool,
) {
    if distance == 0 || distance >= reg.len() {
        return;
    }
    if forward {
        for hi in (distance..reg.len()).rev() {
            circ.cswap(control, &reg[hi], &reg[hi - distance]);
        }
    } else {
        for hi in distance..reg.len() {
            circ.cswap(control, &reg[hi], &reg[hi - distance]);
        }
    }
}

/// Toggle `out` iff the highest `prefix` lanes of `src` are all zero. The
/// peer register supplies restored dirty lenders and is unchanged.
fn toggle_zero_prefix_dirty(
    circ: &mut Circuit,
    src: &[QReg],
    prefix: usize,
    out: &QReg,
    peer: &[QReg],
    clean_scratch: &[&QReg],
) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::{
        kg_prefix_ancilla_count, xor_and_of_khattar_gidney_refs_with_anc,
    };
    use crate::point_add::trailmix_port::arith::mcx::mcx_dirty_ladder;

    assert!(prefix > 0 && prefix < src.len());
    let controls_owned = &src[src.len() - prefix..];
    for q in controls_owned {
        circ.x(q);
    }
    let controls: Vec<&QReg> = controls_owned.iter().collect();
    let clean_refs = clean_scratch.to_vec();
    if lowq_hybrid_clz_kg_mcx_enabled()
        && prefix >= 6
        && clean_refs.len() >= kg_prefix_ancilla_count(prefix)
    {
        xor_and_of_khattar_gidney_refs_with_anc(circ, &controls, out, &clean_refs);
    } else {
        let dirty: Vec<&QReg> = peer.iter().take(prefix.saturating_sub(2)).collect();
        assert_eq!(
            dirty.len(),
            prefix.saturating_sub(2),
            "LOWQ_HYBRID_CLZ peer lender shortage"
        );
        mcx_dirty_ladder(circ, &controls, out, &dirty);
    }
    for q in controls_owned.iter().rev() {
        circ.x(q);
    }
}

/// Toggle `out` iff `active` is set and the lowest `prefix` lanes of `src` are
/// all zero. Lenders may contain arbitrary data and are restored exactly.
fn toggle_active_zero_low_dirty(
    circ: &mut Circuit,
    src: &[QReg],
    prefix: usize,
    active: &QReg,
    out: &QReg,
    lenders: &[&QReg],
) {
    use crate::point_add::trailmix_port::arith::mcx::mcx_dirty_ladder;

    assert!(prefix > 0 && prefix < src.len());
    let controls_owned = &src[..prefix];
    for q in controls_owned {
        circ.x(q);
    }
    let mut controls: Vec<&QReg> = Vec::with_capacity(prefix + 1);
    controls.push(active);
    controls.extend(controls_owned.iter());
    let need = controls.len().saturating_sub(2);
    assert!(
        lenders.len() >= need,
        "LOWQ_EXACT_CTZ lender shortage: need={need} have={}",
        lenders.len()
    );
    mcx_dirty_ladder(circ, &controls, out, &lenders[..need]);
    for q in controls_owned.iter().rev() {
        circ.x(q);
    }
}

/// Compute `transcript = clz(src)` and normalize `src` to an MSB-one word.
/// Each branch bit controls one power-of-two shift and is retained until the
/// inverse restores `src`, so the map is bijective on the full basis space.
fn binary_clz_compute(
    circ: &mut Circuit,
    src: &[QReg],
    peer: &[QReg],
    transcript: &[&QReg],
) {
    assert!(!src.is_empty() && src.len() <= (1usize << transcript.len()));
    for bit in (0..transcript.len()).rev() {
        let distance = 1usize << bit;
        if distance >= src.len() {
            continue;
        }
        toggle_zero_prefix_dirty(circ, src, distance, transcript[bit], peer, &transcript[..bit]);
        controlled_fixed_shift(circ, src, transcript[bit], distance, true);
    }
}

fn binary_clz_uncompute(
    circ: &mut Circuit,
    src: &[QReg],
    peer: &[QReg],
    transcript: &[&QReg],
) {
    for bit in 0..transcript.len() {
        let distance = 1usize << bit;
        if distance >= src.len() {
            continue;
        }
        controlled_fixed_shift(circ, src, transcript[bit], distance, false);
        toggle_zero_prefix_dirty(circ, src, distance, transcript[bit], peer, &transcript[..bit]);
    }
}

fn toggle_prefix_controlled_by_active(
    circ: &mut Circuit,
    ctrls: &[&QReg],
    active: &QReg,
    out: &QReg,
    flag: &QReg,
) {
    match ctrls {
        [] => circ.cx(active, out),
        [c] => circ.ccx(active, c, out),
        [a, b] => {
            circ.ccx(a, b, flag);
            circ.ccx(active, flag, out);
            circ.clear_and(flag, a, b);
        }
        _ => panic!(
            "toggle_prefix_controlled_by_active: expected <=2 KG controls, got {}",
            ctrls.len()
        ),
    }
}

fn toggle_clz_parity_prefix_stream(
    circ: &mut Circuit,
    src: &[QReg],
    active: &QReg,
    out: &QReg,
    scratch: &[&QReg],
) -> bool {
    use crate::point_add::trailmix_port::arith::khattar_gidney::{
        kg_prefix_ancilla_count, KgPrefixAnd,
    };

    if src.len() <= 1 {
        return true;
    }
    let qbits: Vec<&QReg> = src.iter().rev().take(src.len() - 1).collect();
    let nanc = kg_prefix_ancilla_count(qbits.len());
    if scratch.len() < nanc + 1 {
        return false;
    }
    let anc = scratch[..nanc].to_vec();
    let flag = scratch[nanc];

    for &q in &qbits {
        circ.x(q);
    }
    KgPrefixAnd::new(&qbits, &anc)
        .forward(circ, |_, _, _| {})
        .reverse(circ, |c, i, ctrls| {
            if i > 0 {
                toggle_prefix_controlled_by_active(c, ctrls, active, out, flag);
            }
        });
    for &q in qbits.iter().rev() {
        circ.x(q);
    }
    true
}

/// PRE: `s=0`. Deposit `active*ctz(q)` directly into `s`, using `s` itself as
/// the branch transcript. The final left-shift sweep restores multi-hot q while
/// intentionally retaining s.
fn exact_multihot_ctz_deposit(
    circ: &mut Circuit,
    q: &[QReg],
    s: &[&QReg],
    active: &QReg,
    lenders: &[&QReg],
) {
    assert!(!s.is_empty() && s.len() <= 5, "LOWQ exact CTZ output width");
    let prev = circ.push_section("p.hctz.deposit");
    for bit in (0..s.len()).rev() {
        let distance = 1usize << bit;
        if distance >= q.len() {
            continue;
        }
        toggle_active_zero_low_dirty(circ, q, distance, active, s[bit], lenders);
        controlled_fixed_shift(circ, q, s[bit], distance, false);
    }
    for bit in 0..s.len() {
        let distance = 1usize << bit;
        if distance < q.len() {
            controlled_fixed_shift(circ, q, s[bit], distance, true);
        }
    }
    circ.pop_section(&prev);
}

/// Exact gate inverse of `exact_multihot_ctz_deposit`.
/// PRE: `s=active*ctz(q)`. Restores q after the temporary normalization and
/// clears s to zero.
fn exact_multihot_ctz_erase(
    circ: &mut Circuit,
    q: &[QReg],
    s: &[&QReg],
    active: &QReg,
    lenders: &[&QReg],
) {
    assert!(!s.is_empty() && s.len() <= 5, "LOWQ exact CTZ output width");
    let prev = circ.push_section("p.hctz.erase");
    for bit in (0..s.len()).rev() {
        let distance = 1usize << bit;
        if distance < q.len() {
            controlled_fixed_shift(circ, q, s[bit], distance, false);
        }
    }
    for bit in 0..s.len() {
        let distance = 1usize << bit;
        if distance >= q.len() {
            continue;
        }
        controlled_fixed_shift(circ, q, s[bit], distance, true);
        toggle_active_zero_low_dirty(circ, q, distance, active, s[bit], lenders);
    }
    circ.pop_section(&prev);
}

fn collect_dirty_lenders<'a>(
    candidates: impl IntoIterator<Item = &'a QReg>,
    controls: &[&QReg],
    action: &[&QReg],
) -> Vec<&'a QReg> {
    let mut out: Vec<&'a QReg> = Vec::new();
    for q in candidates {
        if controls.iter().any(|c| std::ptr::eq(*c, q))
            || action.iter().any(|a| std::ptr::eq(*a, q))
            || out.iter().any(|d| std::ptr::eq(*d, q))
        {
            continue;
        }
        out.push(q);
    }
    out
}

/// Exact multi-control toggle using arbitrary dirty lenders. Every lender is
/// restored before return; no clean quantum lane is allocated.
fn dirty_controlled_x(
    circ: &mut Circuit,
    controls: &[&QReg],
    target: &QReg,
    candidates: &[&QReg],
    action: &[&QReg],
) {
    use crate::point_add::trailmix_port::arith::mcx::mcx_dirty_ladder;

    let dirty = collect_dirty_lenders(candidates.iter().copied(), controls, action);
    let need = controls.len().saturating_sub(2);
    assert!(
        dirty.len() >= need,
        "Q959 selective-borrow lender shortage: controls={} need={} have={}",
        controls.len(),
        need,
        dirty.len()
    );
    mcx_dirty_ladder(circ, controls, target, &dirty[..need]);
}

pub(crate) fn dirty_controlled_inc_suffix(
    circ: &mut Circuit,
    selector: &[&QReg],
    target: &[&QReg],
    lo: usize,
    subtract: bool,
    candidates: &[&QReg],
) {
    let action = target.to_vec();
    for i in (lo + 1..target.len()).rev() {
        let lower = target[lo..i].to_vec();
        if subtract {
            for q in &lower {
                circ.x(q);
            }
        }
        let mut controls = selector.to_vec();
        controls.extend(lower.iter().copied());
        dirty_controlled_x(circ, &controls, target[i], candidates, &action);
        if subtract {
            for q in lower.iter().rev() {
                circ.x(q);
            }
        }
    }
    dirty_controlled_x(circ, selector, target[lo], candidates, &action);
}

fn dirty_controlled_add_const(
    circ: &mut Circuit,
    selector: &[&QReg],
    target: &[&QReg],
    value: usize,
    subtract: bool,
    candidates: &[&QReg],
) {
    let mask = (1usize << target.len()) - 1;
    let value = value & mask;
    for bit in 0..target.len() {
        if (value >> bit) & 1 == 1 {
            dirty_controlled_inc_suffix(circ, selector, target, bit, subtract, candidates);
        }
    }
}

/// Add or subtract the promised nonzero source bit length directly into the
/// existing five-bit target. Scanning from high to low, the borrowed selector
/// gate latches exactly once at the source MSB. One unit update per remaining
/// position then deposits `msb - lo + 1`; a final controlled constant update
/// supplies `lo`. The high suffix stays complemented across adjacent selectors
/// instead of being rebuilt for every candidate MSB.
fn direct_bitlen_update(
    circ: &mut Circuit,
    src: &[QReg],
    peer: &[QReg],
    lo: usize,
    target: &[&QReg],
    active: &QReg,
    selector_gate: &QReg,
    subtract: bool,
    extra_lenders: &[&QReg],
) {
    let lo = lo.min(src.len().saturating_sub(1));
    let candidates: Vec<&QReg> = peer
        .iter()
        .chain(src.iter())
        .chain(extra_lenders.iter().copied())
        .collect();
    let mut action = target.to_vec();
    action.push(selector_gate);
    for k in (lo..src.len()).rev() {
        let mut selector = Vec::with_capacity(src.len() - k + 1);
        selector.push(active);
        selector.push(&src[k]);
        selector.extend(src[k + 1..].iter());
        // The selector is one-hot over k. Once it fires, every lower-k selector
        // is false because the complemented suffix contains the true MSB.
        dirty_controlled_x(circ, &selector, selector_gate, &candidates, &action);
        if lowq_q956_off_borrow_enabled() {
            // `selector_gate` aliases counter[0]. It is guaranteed clean only
            // when active, so every read must carry the active predicate too.
            dirty_controlled_inc_suffix(
                circ,
                &[active, selector_gate],
                target,
                0,
                subtract,
                &candidates,
            );
        } else {
            dirty_controlled_inc_suffix(
                circ,
                &[selector_gate],
                target,
                0,
                subtract,
                &candidates,
            );
        }
        if k > lo {
            circ.x(&src[k]);
        }
    }
    for q in src[lo + 1..].iter().rev() {
        circ.x(q);
    }

    // On the promised support, active implies that the selected window is
    // nonzero, so exactly one MSB selector fired and selector_gate == active.
    circ.cx(active, selector_gate);
    if lo != 0 {
        dirty_controlled_add_const(circ, &[active], target, lo, subtract, &candidates);
    }
}

fn direct_bitlen_diff_update(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    lo_a: usize,
    lo_b: usize,
    target: &[&QReg],
    active: &QReg,
    selector_gate: &QReg,
    subtract_diff: bool,
    extra_lenders: &[&QReg],
) {
    let prev = circ.push_section("p.dbitlen");
    direct_bitlen_update(
        circ,
        a,
        b,
        lo_a,
        target,
        active,
        selector_gate,
        subtract_diff,
        extra_lenders,
    );
    direct_bitlen_update(
        circ,
        b,
        a,
        lo_b,
        target,
        active,
        selector_gate,
        !subtract_diff,
        extra_lenders,
    );
    circ.pop_section(&prev);
}

fn direct_bitlen_diff_parity(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    lo_a: usize,
    lo_b: usize,
    out: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
) {
    let prev = circ.push_section("p.dbitlen.parity");
    let action = [out];
    for (src, peer, lo) in [(a, b, lo_a), (b, a, lo_b)] {
        let lo = lo.min(src.len().saturating_sub(1));
        let candidates: Vec<&QReg> = peer
            .iter()
            .chain(src.iter())
            .chain(extra_lenders.iter().copied())
            .collect();
        for k in (lo..src.len()).rev() {
            if (k + 1) & 1 == 1 {
                let mut selector = Vec::with_capacity(src.len() - k + 1);
                selector.push(active);
                selector.push(&src[k]);
                selector.extend(src[k + 1..].iter());
                dirty_controlled_x(circ, &selector, out, &candidates, &action);
            }
            if k > lo {
                circ.x(&src[k]);
            }
        }
        for q in src[lo + 1..].iter().rev() {
            circ.x(q);
        }
    }
    circ.pop_section(&prev);
}

fn hybrid_transcript_width(max_window_len: usize) -> usize {
    let branch_bits = if max_window_len <= 1 {
        0
    } else {
        usize::BITS as usize - (max_window_len - 1).leading_zeros() as usize
    };
    branch_bits.max(5)
}

const BORROWED_TRANSCRIPT_LOGICAL_WIDTH: usize = 7;
#[doc(hidden)]
pub const Q944_RESIDUAL_HCLZ_ROWS: [usize; 25] = [
    292, 293, 294, 301, 302, 303, 304, 319, 320, 321, 322, 323, 324, 325, 326, 334, 335,
    336, 337, 338, 343, 344, 349, 357, 385,
];
#[doc(hidden)]
pub const Q944_RESIDUAL_NON_HCLZ_ROWS: [usize; 10] =
    [311, 312, 313, 314, 331, 332, 351, 352, 355, 356];
#[doc(hidden)]
pub const Q948_DIRECT_HCLZ_BINDING_ROWS: [usize; 6] = [371, 372, 381, 382, 383, 384];
#[doc(hidden)]
pub const Q947_DIRECT_HCLZ_NEW_ROWS: [usize; 10] =
    [295, 296, 297, 298, 345, 346, 348, 360, 369, 370];
#[doc(hidden)]
pub const Q947_DIRECT_HCLZ_BINDING_ROWS: [usize; 16] = [
    295, 296, 297, 298, 345, 346, 348, 360, 369, 370, 371, 372, 381, 382, 383, 384,
];
#[doc(hidden)]
pub const Q946_SECOND_RELEASE_DIRECT_HCLZ_SIX_ROW_EXTENSION: [usize; 6] =
    [307, 308, 309, 310, 353, 354];
#[doc(hidden)]
pub const Q946_SECOND_RELEASE_DIRECT_HCLZ_RESIDUAL_TIES: [usize; 12] =
    [306, 315, 316, 317, 327, 328, 329, 330, 333, 350, 358, 359];
#[doc(hidden)]
pub const Q946_SECOND_RELEASE_DIRECT_HCLZ_ROWS: [usize; 18] = [
    306, 307, 308, 309, 310, 315, 316, 317, 327, 328, 329, 330, 333, 350, 353, 354, 358, 359,
];

#[doc(hidden)]
pub const Q945_DIRTY_PARITY_MICROKERNEL_COMMIT: &str =
    "8cd51b5df0ef18373d38fcee5ce77ddabf4e58cb";
#[doc(hidden)]
pub const Q945_DIRTY_PARITY_MICROKERNEL_TREE: &str =
    "c74ce2b47ff5a021396393f296ff8677f2e69244";
#[doc(hidden)]
pub const Q945_DIRTY_PARITY_MICROKERNEL_BLOB: &str =
    "ae3b46c5dc1b63546587066cad94846e8b1222c1";

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
enum BorrowedTranscriptSubstep {
    Division,
    Multiply,
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
enum BorrowedTranscriptLoanKind {
    PreterminalCounter,
    Row379AHigh,
    Row380ForwardCbHigh,
    Row380ReverseCaHigh,
    Q945LocalHost(Q945Host, Q945HclzForm),
    ProofHarness,
}

#[derive(Clone, Copy)]
enum BorrowedTranscriptPreparation<'a> {
    AlreadyZero,
    ComplementOf(&'a QReg),
}

#[derive(Clone, Copy)]
pub(crate) struct BorrowedTranscriptLoan<'a> {
    lane: &'a QReg,
    kind: BorrowedTranscriptLoanKind,
    row: usize,
    inverse: bool,
    substep: BorrowedTranscriptSubstep,
    preparation: BorrowedTranscriptPreparation<'a>,
}

#[derive(Clone, Copy)]
struct BorrowedTranscriptLoans<'a> {
    update: Option<BorrowedTranscriptLoan<'a>>,
    parity: Option<BorrowedTranscriptLoan<'a>>,
    q945_local_class: bool,
}

#[derive(Clone, Copy)]
enum Q945NarrowCarry<'a> {
    Borrow {
        lane: &'a QReg,
        dirty_parity: Option<&'a QReg>,
        host: Q945Host,
        row: usize,
        substep: Q945Substep,
    },
    Row364DivisionLower80 {
        carry: &'a QReg,
        not_gate: &'a QReg,
        dirty_parity: Option<&'a QReg>,
        row: usize,
        substep: Q945Substep,
    },
    ResidualDirtyParity {
        dirty_parity: &'a QReg,
        row: usize,
        substep: Q945Substep,
    },
}

#[derive(Clone, Copy)]
struct Q945DirtyParityArithmetic<'a> {
    lane: &'a QReg,
    row: usize,
    substep: Q945Substep,
}

impl<'a> Q945NarrowCarry<'a> {
    const fn dirty_parity_arithmetic(self) -> Option<Q945DirtyParityArithmetic<'a>> {
        match self {
            Self::Borrow {
                dirty_parity,
                row,
                substep,
                ..
            }
            | Self::Row364DivisionLower80 {
                dirty_parity,
                row,
                substep,
                ..
            } => match dirty_parity {
                Some(lane) => Some(Q945DirtyParityArithmetic {
                    lane,
                    row,
                    substep,
                }),
                None => None,
            },
            Self::ResidualDirtyParity {
                dirty_parity,
                row,
                substep,
            } => Some(Q945DirtyParityArithmetic {
                lane: dirty_parity,
                row,
                substep,
            }),
        }
    }
}

impl<'a> BorrowedTranscriptLoans<'a> {
    const fn none() -> Self {
        Self {
            update: None,
            parity: None,
            q945_local_class: false,
        }
    }

    const fn shared(loan: Option<BorrowedTranscriptLoan<'a>>) -> Self {
        Self {
            update: loan,
            parity: loan,
            q945_local_class: false,
        }
    }

    const fn loan(self, form: Q945HclzForm) -> Option<BorrowedTranscriptLoan<'a>> {
        match form {
            Q945HclzForm::Update => self.update,
            Q945HclzForm::Parity => self.parity,
        }
    }

    const fn q945_local_borrowed(self, form: Q945HclzForm) -> Option<bool> {
        if self.q945_local_class {
            Some(self.loan(form).is_some())
        } else {
            None
        }
    }
}

impl BorrowedTranscriptLoan<'_> {
    fn assert_disjoint(self, forbidden: &[&QReg]) {
        assert!(
            forbidden
                .iter()
                .all(|lane| !std::ptr::eq(*lane, self.lane)),
            "borrowed transcript {:?} row {} {:?} {:?} aliases a transcript operand",
            self.kind,
            self.row,
            if self.inverse { "reverse" } else { "forward" },
            self.substep,
        );
    }


    fn acquire_zero(self, circ: &mut Circuit) {
        if let BorrowedTranscriptPreparation::ComplementOf(control) = self.preparation {
            assert!(
                !std::ptr::eq(control, self.lane),
                "borrowed transcript relation control aliases its lender"
            );
            circ.x(self.lane);
            circ.cx(control, self.lane);
        }
    }

    fn restore_relation(self, circ: &mut Circuit) {
        if let BorrowedTranscriptPreparation::ComplementOf(control) = self.preparation {
            circ.cx(control, self.lane);
            circ.x(self.lane);
        }
    }
}

/// Allocate the low six transcript lanes and append one certified-clean lender
/// as the logical high lane. The body must restore every transcript lane to its
/// entry value. Owned lanes are reset/freed; the borrowed lane is released by
/// retaining ownership in its source register.
fn with_hybrid_transcript<R>(
    circ: &mut Circuit,
    logical_width: usize,
    loan: Option<BorrowedTranscriptLoan<'_>>,
    forbidden: &[&QReg],
    body: impl FnOnce(&mut Circuit, &[&QReg]) -> R,
) -> R {
    let use_loan = loan.filter(|_| logical_width == BORROWED_TRANSCRIPT_LOGICAL_WIDTH);
    if let Some(loan) = use_loan {
        assert!(lowq_borrowed_transcript_experiment_enabled());
        loan.assert_disjoint(forbidden);
    }
    let owned_width = logical_width - usize::from(use_loan.is_some());
    assert!(owned_width >= 5, "hybrid CLZ requires five low transcript lanes");
    let owned = circ.alloc_qreg_bits("hybrid.clz", owned_width);
    let mut transcript: Vec<&QReg> = owned.iter().collect();
    if let Some(loan) = use_loan {
        transcript.push(loan.lane);
    }
    assert_eq!(transcript.len(), logical_width);
    if let Some(loan) = use_loan {
        loan.acquire_zero(circ);
    }
    let result = body(circ, &transcript);
    if let Some(loan) = use_loan {
        loan.restore_relation(circ);
        if let BorrowedTranscriptLoanKind::Q945LocalHost(host, form) = loan.kind {
            circ.b.record_lowq_liveness_marker(format!(
                concat!(
                    "q945_hclz_host=1;row={};substep={};form={};",
                    "host={};bit={};physical_id={};restored_by_uncompute=true"
                ),
                loan.row,
                match loan.substep {
                    BorrowedTranscriptSubstep::Division => "division",
                    BorrowedTranscriptSubstep::Multiply => "multiply",
                },
                form.label(),
                host.register.label(),
                host.bit,
                loan.lane.id(),
            ));
        }
    }
    for lane in owned {
        circ.zero_and_free(lane);
    }
    result
}

fn selective_direct_bitlen_needed(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    lo_a: usize,
    lo_b: usize,
    form: Q945HclzForm,
    q945_local_borrowed: Option<bool>,
) -> bool {
    if !lowq_q959_selective_borrow_enabled() {
        return false;
    }
    circ.flush_pending_frees();
    let aw = a.len().saturating_sub(lo_a.min(a.len().saturating_sub(1)));
    let bw = b.len().saturating_sub(lo_b.min(b.len().saturating_sub(1)));
    let baseline_peak_target = if lowq_q949_affine_counter_enabled() {
        949
    } else if lowq_q954_srot_counter7_enabled() {
        954
    } else if lowq_q956_off_borrow_enabled() {
        956
    } else if lowq_q957_target683_enabled() {
        957
    } else if lowq_q958_gated_compare_enabled() {
        958
    } else {
        959
    };
    let logical_width = hybrid_transcript_width(aw.max(bw));
    let baseline_direct = circ.b.active_qubits as usize + logical_width > baseline_peak_target;
    if !lowq_q948_direct_hclz_peak_guard_enabled()
        || !circ.lowq_q948_direct_hclz_peak_guard_active
    {
        return baseline_direct;
    }

    // The hybrid transcript itself has `logical_width` lanes. The measured
    // cap-681 trace reaches one lane beyond active+logical_width inside the
    // prefix/CLZ implementation, so account for that literal internal lane.
    let projected_hybrid_peak = circ.b.active_qubits as usize + logical_width + 1;
    let direct_target = if lowq_q944_residual_one_lane_cut_enabled() {
        944
    } else if lowq_q945_local_hosts_enabled() {
        945
    } else if q946_second_ownership_release_requested() {
        946
    } else if q947_passenger_direct_hclz_requested() {
        947
    } else {
        948
    };
    assert!(
        projected_hybrid_peak > direct_target,
        "direct HCLZ binding context no longer exceeds the target"
    );
    let guarded_direct = if lowq_q944_residual_one_lane_cut_enabled() {
        true
    } else if q945_local_hosts_requested() {
        match q945_local_borrowed {
            Some(true) => {
                assert!(
                    !baseline_direct,
                    "Q945 local HCLZ loan unexpectedly entered the baseline direct route"
                );
                false
            }
            Some(false) | None => true,
        }
    } else {
        assert!(q945_local_borrowed.is_none());
        true
    };
    if guarded_direct && !baseline_direct {
        circ.b.record_lowq_liveness_marker(format!(
            concat!(
                "direct_hclz_peak_guard=1;form={};active={};logical_width={};",
                "projected_hybrid_peak={};target={}"
            ),
            form.label(),
            circ.b.active_qubits,
            logical_width,
            projected_hybrid_peak,
            direct_target,
        ));
    }
    baseline_direct || guarded_direct
}

/// Deposit `active*(bitlen(a)-bitlen(b))` into the existing five-bit shift
/// register. Equal full register widths imply
/// `bitlen(a)-bitlen(b) = clz(b)-clz(a)` even when the audited low windows
/// differ. A single seven-bit transcript is reused sequentially.
fn hybrid_bitlen_diff_update(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    lo_a: usize,
    lo_b: usize,
    target: &[&QReg],
    active: &QReg,
    subtract_diff: bool,
    transcript_loan: Option<BorrowedTranscriptLoan<'_>>,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::{
        ctrl_add, ctrl_add_dirty_lenders, ctrl_sub, ctrl_sub_dirty_lenders,
    };

    assert_eq!(a.len(), b.len(), "LOWQ_HYBRID_CLZ requires equal full widths");
    assert_eq!(target.len(), 5, "LOWQ_HYBRID_CLZ target width");
    let prev = circ.push_section("p.hclz");
    let a_window = &a[lo_a.min(a.len() - 1)..];
    let b_window = &b[lo_b.min(b.len() - 1)..];
    let logical_width = hybrid_transcript_width(a_window.len().max(b_window.len()));
    let target_refs = target.to_vec();
    let noalloc_add = lowq_hybrid_clz_noalloc_add_enabled();
    let forbidden: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(target.iter().copied())
        .chain(std::iter::once(active))
        .collect();

    with_hybrid_transcript(
        circ,
        logical_width,
        transcript_loan,
        &forbidden,
        |circ, transcript| {
            let low_refs = transcript[..target.len()].to_vec();
            binary_clz_compute(circ, a_window, b, transcript);
            if subtract_diff {
                if noalloc_add {
                    ctrl_add_dirty_lenders(circ, active, &target_refs, &low_refs);
                } else {
                    ctrl_add(circ, active, &target_refs, &low_refs);
                }
            } else if noalloc_add {
                ctrl_sub_dirty_lenders(circ, active, &target_refs, &low_refs);
            } else {
                ctrl_sub(circ, active, &target_refs, &low_refs);
            }
            binary_clz_uncompute(circ, a_window, b, transcript);

            binary_clz_compute(circ, b_window, a, transcript);
            if subtract_diff {
                if noalloc_add {
                    ctrl_sub_dirty_lenders(circ, active, &target_refs, &low_refs);
                } else {
                    ctrl_sub(circ, active, &target_refs, &low_refs);
                }
            } else if noalloc_add {
                ctrl_add_dirty_lenders(circ, active, &target_refs, &low_refs);
            } else {
                ctrl_add(circ, active, &target_refs, &low_refs);
            }
            binary_clz_uncompute(circ, b_window, a, transcript);
        },
    );
    circ.pop_section(&prev);
}

fn hybrid_bitlen_diff_parity(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    lo_a: usize,
    lo_b: usize,
    out: &QReg,
    active: &QReg,
    transcript_loan: Option<BorrowedTranscriptLoan<'_>>,
) {
    assert_eq!(a.len(), b.len(), "LOWQ_HYBRID_CLZ requires equal full widths");
    let prev = circ.push_section("p.hclz.parity");
    let a_window = &a[lo_a.min(a.len() - 1)..];
    let b_window = &b[lo_b.min(b.len() - 1)..];
    let logical_width = hybrid_transcript_width(a_window.len().max(b_window.len()));
    let forbidden: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain([out, active])
        .collect();

    with_hybrid_transcript(
        circ,
        logical_width,
        transcript_loan,
        &forbidden,
        |circ, transcript| {
            if lowq_hybrid_clz_prefix_parity_enabled()
                && toggle_clz_parity_prefix_stream(circ, a_window, active, out, transcript)
                && toggle_clz_parity_prefix_stream(circ, b_window, active, out, transcript)
            {
                // Fast exact parity path: clz(x) mod 2 is the XOR of all non-empty
                // top-zero prefix flags of x. No controlled shifts are needed.
            } else {
                binary_clz_compute(circ, a_window, b, transcript);
                circ.ccx(active, transcript[0], out);
                binary_clz_uncompute(circ, a_window, b, transcript);
                binary_clz_compute(circ, b_window, a, transcript);
                circ.ccx(active, transcript[0], out);
                binary_clz_uncompute(circ, b_window, a, transcript);
            }
        },
    );
    circ.pop_section(&prev);
}

/*
 * The owned-only implementation formerly lived here. Keeping transcript
 * allocation behind `with_hybrid_transcript` makes the default-off path exact:
 * with no loan it still allocates and frees the same logical width.
 */

/// `_middle` form of the clz-diff compute-USE-uncompute pattern: deposits the two
/// bitlen positions into the internal `pa`/`pb` ancillae, FOLDS the diff
/// d = bitlen(a)-bitlen(b) (windowed) INTO `pa`, runs `body(circ, &pa)` with `pa`
/// holding the diff, then restores `pa` and un-deposits to |0>. No caller-supplied
/// diff register -- `pa` IS the diff, so nothing extra is live at the peak (this is
/// the `shrunken_pz_divide_forward` peak section). `w` sizes pa/pb (must hold the window MSB
/// index and the signed diff). Scans un-nested (one KG ancilla set live at a time).
fn clz_diff_body_middle(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    w: usize,
    lo_a: usize,
    lo_b: usize,
    body: impl FnOnce(&mut Circuit, &[QReg]),
) {
    use crate::point_add::trailmix_port::arith::ripple_add::add_const;
    let pbl = circ.push_section("p.bitlen");
    let aw: Vec<&QReg> = a[lo_a..a.len()].iter().collect();
    let bw: Vec<&QReg> = b[lo_b..b.len()].iter().collect();
    let pa = circ.alloc_qreg_bits("clzm.pa", w);
    let pb = circ.alloc_qreg_bits("clzm.pb", w);
    let add_pa = |circ: &mut Circuit, pa: &[QReg], v: i64| {
        let val = i128::from(v).rem_euclid(1i128 << w) as u128;
        let bytes: Vec<u8> = (0..w.div_ceil(8)).map(|i| (val >> (8 * i)) as u8).collect();
        add_const(circ, pa, &bytes);
    };
    let (na, nb) = (aw.len(), bw.len());
    // UN-NESTED scans: deposit pos_a then pos_b SEQUENTIALLY (one KG ancilla set
    // live at a time, not both nested). `bit_length_lean_middle` with a `|_| false`
    // body deposits pos (na -> MSB index) and leaves it; the pos-telescoping is a
    // fixed XOR-set gated on `src` only (independent of pos's value), hence
    // self-inverse -- the SAME call run again returns pos (MSB index -> na), so it
    // doubles as the un-deposit phase.
    xor_const(circ, &pa, na);
    bit_length_lean_middle(circ, &aw, &pa, |_| false); // pa = pos_a
    xor_const(circ, &pb, nb);
    bit_length_lean_middle(circ, &bw, &pb, |_| false); // pb = pos_b

    let const_fold = lowq_clz_diff_const_fold_enabled();
    if const_fold {
        // Constants commute across the subtract. This is the q980 reduction:
        // one modular constant add instead of two, with no extra live wires.
        {
            let par: Vec<&QReg> = pa.iter().collect();
            let pbr: Vec<&QReg> = pb.iter().collect();
            sub_refs(circ, &par, &pbr);
        }
        add_pa(circ, &pa, lo_a as i64 - lo_b as i64);
    } else {
        {
            let par: Vec<&QReg> = pa.iter().collect();
            let pbr: Vec<&QReg> = pb.iter().collect();
            add_pa(circ, &pa, 1 + lo_a as i64);
            sub_refs(circ, &par, &pbr);
        }
        add_pa(circ, &pa, -(1 + lo_b as i64));
    }

    body(circ, &pa); // USE pa (= diff)

    if const_fold {
        {
            let par: Vec<&QReg> = pa.iter().collect();
            let pbr: Vec<&QReg> = pb.iter().collect();
            add_refs(circ, &par, &pbr);
        }
        add_pa(circ, &pa, lo_b as i64 - lo_a as i64);
    } else {
        add_pa(circ, &pa, 1 + lo_b as i64);
        {
            let par: Vec<&QReg> = pa.iter().collect();
            let pbr: Vec<&QReg> = pb.iter().collect();
            add_refs(circ, &par, &pbr);
        }
        add_pa(circ, &pa, -(1 + lo_a as i64));
    }

    // un-deposit (self-inverse clean=false calls, reverse order).
    bit_length_lean_middle(circ, &bw, &pb, |_| false); // pb -> nb
    xor_const(circ, &pb, nb); // pb -> 0
    bit_length_lean_middle(circ, &aw, &pa, |_| false); // pa -> na
    xor_const(circ, &pa, na); // pa -> 0
    for q in pa {
        circ.zero_and_free(q);
    }
    for q in pb {
        circ.zero_and_free(q);
    }
    circ.pop_section(&pbl);
}

/// Rotate-LEFT `reg` in place by the quantum amount `s` (= reg << s, since the
/// aligned value's bitlen <= reg width so no nonzero bit wraps). Uses the ACYCLIC
/// `barrel_shift_inplace` (exactly `s.len()` layers, no wrap) rather than
/// `controlled_cyclic_rotate` (s.len()+1 full-width layers incl. a spurious
/// offset layer, + cyclic wrap churn): ~1.28x fewer cswaps. The no-wrap
/// precondition (top s bits of reg are |0>) is exactly the existing one.
/// forward=true is `<< s`; forward=false (restore) is `>> s`, Fredkin self-inverse.
fn barrel_shift_refs(circ: &mut Circuit, reg: &[QReg], s: &[&QReg], forward: bool) {
    let n = reg.len();
    if n == 0 || s.is_empty() {
        return;
    }
    let prev = circ.push_section("p.shift");
    let layers: Box<dyn Iterator<Item = usize>> = if forward {
        Box::new(0..s.len())
    } else {
        Box::new((0..s.len()).rev())
    };
    for bit in layers {
        let distance = 1usize << bit;
        if distance >= n {
            continue;
        }
        let pairs: Box<dyn Iterator<Item = usize>> = if forward {
            Box::new((distance..n).rev())
        } else {
            Box::new(distance..n)
        };
        for hi in pairs {
            let lo = hi - distance;
            circ.cx(&reg[lo], &reg[hi]);
            circ.ccx(s[bit], &reg[hi], &reg[lo]);
            circ.cx(&reg[lo], &reg[hi]);
        }
    }
    circ.pop_section(&prev);
}

fn rotate_left(circ: &mut Circuit, reg: &[QReg], s: &[&QReg]) {
    barrel_shift_refs(circ, reg, s, true);
}
fn rotate_right(circ: &mut Circuit, reg: &[QReg], s: &[&QReg]) {
    barrel_shift_refs(circ, reg, s, false);
}

/// Shift by one under `active AND off`. On the Q956 route `off` is a counter
/// lane that may be one on inactive branches, so using it as a lone Fredkin
/// control would corrupt those branches. The three-control swap is emitted
/// directly with restored dirty lenders and allocates no conjunction lane.
fn rotate_one_by_off(
    circ: &mut Circuit,
    reg: &[QReg],
    active: &QReg,
    off: &QReg,
    forward: bool,
    candidates: &[&QReg],
) {
    if !lowq_q956_off_borrow_enabled() {
        let control = [off];
        if forward {
            rotate_left(circ, reg, &control);
        } else {
            rotate_right(circ, reg, &control);
        }
        return;
    }
    if reg.len() < 2 {
        return;
    }

    let prev = circ.push_section("p.shift.off-borrow");
    let action: Vec<&QReg> = reg.iter().collect();
    let pairs: Box<dyn Iterator<Item = usize>> = if forward {
        Box::new((1..reg.len()).rev())
    } else {
        Box::new(1..reg.len())
    };
    for hi in pairs {
        let lo = hi - 1;
        circ.cx(&reg[lo], &reg[hi]);
        let controls = [active, off, &reg[hi]];
        dirty_controlled_x(circ, &controls, &reg[lo], candidates, &action);
        circ.cx(&reg[lo], &reg[hi]);
    }
    circ.pop_section(&prev);
}

/// `q[i] ^= active AND (s == i)` = `q ^= active·(1<<s)` -- the q-demux via KG
/// `unary_iterate_log_star` (~2 ccx/step) instead of a per-bit `eq_const_inplace` loop
/// (~58 tof/bit, ~30x more). active=0 => s masked to 0 => only i=0 gate fires,
/// `ANDed` with active=0 -> no-op. Self-inverse; `s` restored on exit.
fn set_bit_at_s_gated(
    circ: &mut Circuit,
    q_div: &[QReg],
    s: &[&QReg],
    active: &QReg,
    borrowed_gate: &QReg,
    lenders: &[&QReg],
) {
    let n_pad = q_div.len();
    if n_pad == 0 {
        return;
    }
    let prev = circ.push_section("p.demux");
    if lowq_q959_selective_borrow_enabled() {
        let mask_borrowed_reads = lowq_q956_off_borrow_enabled();
        let mut action: Vec<&QReg> = q_div.iter().collect();
        action.push(borrowed_gate);
        for (i, target) in q_div.iter().enumerate() {
            for (bit, q) in s.iter().enumerate() {
                if (i >> bit) & 1 == 0 {
                    circ.x(q);
                }
            }
            let mut controls = Vec::with_capacity(s.len() + 1);
            controls.push(active);
            controls.extend(s.iter().copied());
            dirty_controlled_x(circ, &controls, borrowed_gate, lenders, &action);
            if mask_borrowed_reads {
                circ.ccx(active, borrowed_gate, target);
            } else {
                circ.cx(borrowed_gate, target);
            }
            dirty_controlled_x(circ, &controls, borrowed_gate, lenders, &action);
            for (bit, q) in s.iter().enumerate().rev() {
                if (i >> bit) & 1 == 0 {
                    circ.x(q);
                }
            }
        }
        circ.pop_section(&prev);
        return;
    }

    use crate::point_add::trailmix_port::arith::khattar_gidney::unary_iterate_log_star;
    unary_iterate_log_star(circ, s, n_pad, |c, i, gate| {
        c.ccx(active, gate, &q_div[i]);
    });
    circ.pop_section(&prev);
}

/// Unconditional `a -= b` (mod 2^len) via two's complement (X-bracket + add).
fn sub_refs(circ: &mut Circuit, a: &[&QReg], b: &[&QReg]) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::ctrl_sub;
    let one = circ.alloc_qreg("sm.one");
    circ.x(&one);
    ctrl_sub(circ, &one, a, b); // gated on |1> = unconditional
    circ.x(&one);
    circ.zero_and_free(one);
}

/// Controlled decrement `s -= 1` iff `g` (X-bracket + controlled increment).
fn ctrl_dec(circ: &mut Circuit, g: &QReg, s: &[QReg]) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::cinc_khattar_gidney;
    for q in s {
        circ.x(q);
    }
    cinc_khattar_gidney(circ, s, g); // a=s, ctrl=g
    for q in s {
        circ.x(q);
    }
}

/// Controlled increment `s += 1` iff `g`.
fn ctrl_inc(circ: &mut Circuit, g: &QReg, s: &[QReg]) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::cinc_khattar_gidney;
    cinc_khattar_gidney(circ, s, g);
}

fn ctrl_inc_refs(circ: &mut Circuit, g: &QReg, s: &[&QReg]) {
    use crate::point_add::trailmix_port::arith::khattar_gidney::cinc_khattar_gidney_refs;
    cinc_khattar_gidney_refs(circ, s, g);
}

fn ctrl_dec_refs(circ: &mut Circuit, g: &QReg, s: &[&QReg]) {
    for q in s {
        circ.x(q);
    }
    ctrl_inc_refs(circ, g, s);
    for q in s {
        circ.x(q);
    }
}

fn ctrl_inc_by_off(
    circ: &mut Circuit,
    active: &QReg,
    off: &QReg,
    s: &[&QReg],
    candidates: &[&QReg],
) {
    if lowq_q956_off_borrow_enabled() {
        dirty_controlled_inc_suffix(circ, &[active, off], s, 0, false, candidates);
    } else {
        ctrl_inc_refs(circ, off, s);
    }
}

fn ctrl_dec_by_off(
    circ: &mut Circuit,
    active: &QReg,
    off: &QReg,
    s: &[&QReg],
    candidates: &[&QReg],
) {
    if lowq_q956_off_borrow_enabled() {
        dirty_controlled_inc_suffix(circ, &[active, off], s, 0, true, candidates);
    } else {
        ctrl_dec_refs(circ, off, s);
    }
}

/// Unconditional `a += b` (mod 2^len) via a |1>-gated controlled add.
fn add_refs(circ: &mut Circuit, a: &[&QReg], b: &[&QReg]) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::ctrl_add;
    let one = circ.alloc_qreg("sm.one_a");
    circ.x(&one);
    ctrl_add(circ, &one, a, b);
    circ.x(&one);
    circ.zero_and_free(one);
}

/// Unpacked PZ state-machine registers. gcd pair (`a_gcd=A`, `b_gcd=B`) shrinks;
/// cofactor pair (ca=|a|, cb=|b|) grows. `q_div/q_mul` are the quotient pads
/// (~one quotient, ~26 bits each): `q_div` is built by the division (`q_div^=1`<<s),
/// swapped to `q_mul`, and DRAINED by the multiply (a += b<<`ctz(q_mul)`, clearing
/// it) -- the pipelined drain is what keeps the quotient record at one-quotient
/// size instead of a full ~256-bit tape. NOT removable (scripts/
/// `pz_fused_nopad_proto.py`: fusing gives the right inverse but s-recovery from
/// the cofactors mismatches ~30%, and an undrained pad accumulates a full tape).
pub struct PzSmRegs {
    pub a_gcd: Vec<QReg>,
    pub b_gcd: Vec<QReg>,
    pub ca: Vec<QReg>,
    pub cb: Vec<QReg>,
    pub q_div: Vec<QReg>,
    pub q_mul: Vec<QReg>,
}

/// Single-qubit state flags + sign. Invariant matches `pz_big_step`.
pub struct PzSmFlags {
    pub div_active: QReg,
    pub mul_active: QReg,
    pub offset: QReg,
    pub parity: QReg,
    pub sgn: QReg,
}

/// Load/unload the classical constant `c` into `reg` via X gates (self-inverse).
fn xor_const(circ: &mut Circuit, reg: &[QReg], c: usize) {
    for (j, q) in reg.iter().enumerate() {
        if (c >> j) & 1 == 1 {
            circ.x(q);
        }
    }
}

/// Magnitude compare `out ^= (a < b)` narrowed to the schedule window
/// `[lo, min(a.len, b.len))`. Used for the ALIGNED offset/o compares where a and
/// b share a bitlen (MSB guaranteed in [lo, hi) by the schedule), so the top bits
/// decide the order; a tie below `lo` (prob ~2^-(hi-lo) per the window width)
/// flips the result -- within the whole-pass tail tolerance. Forward and inverse
/// substeps call this with the same `lo`, so the (possibly-wrong) flag is
/// computed identically both ways and round-trips cleanly. Restores a,b.
/// NOT for the magnitude GATES (`g_mul/g_div)`: there A,B get arbitrarily close at
/// the div<->mul transition, so a deep tie is common, not a 2^-w tail.
fn narrow_lt(circ: &mut Circuit, a: &[QReg], b: &[QReg], out: &QReg, lo: usize) {
    let hi = a.len().min(b.len());
    let lo = lo.min(hi.saturating_sub(1));
    let ar: Vec<&QReg> = a[lo..hi].iter().collect();
    let br: Vec<&QReg> = b[lo..hi].iter().collect();
    borrow_compare_refs(circ, &ar, &br, out);
}

/// Toggle `out` by `active AND (a < b)` without materializing a separate
/// comparison result. The comparator still restores its one clean carry lane,
/// so this saves one peak-live qubit and one complete comparator replay.
fn narrow_lt_controlled(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    out: &QReg,
    active: &QReg,
    lo: usize,
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    let hi = a.len().min(b.len());
    let lo = lo.min(hi.saturating_sub(1));
    if let Some(Q945NarrowCarry::Borrow {
        lane,
        dirty_parity: Some(parity),
        host,
        row,
        substep,
    }) = q945_carry
    {
        if std::ptr::eq(lane, active) {
            assert!(lowq_q945_dirty_parity_arithmetic_enabled());
            let ar: Vec<&QReg> = a[lo..hi].iter().collect();
            let br: Vec<&QReg> = b[lo..hi].iter().collect();
            strict_compare_gated_dirty_carry_refs(circ, &ar, &br, active, out, parity);
            circ.b.record_lowq_liveness_marker(format!(
                concat!(
                    "q944_alias_safe_narrow_compare=1;row={};substep={};",
                    "q945_host={};q945_bit={};active_physical={};carry=parity;",
                    "compared_bits={};allocation_free=true;active_restored=true;",
                    "carry_restored=true;operands_restored=true"
                ),
                row,
                substep.label(),
                host.register.label(),
                host.bit,
                active.id(),
                hi - lo,
            ));
            return;
        }
    }
    if let Some(Q945NarrowCarry::ResidualDirtyParity {
        dirty_parity,
        row,
        substep,
    }) = q945_carry
    {
        assert!(lowq_q944_residual_one_lane_cut_enabled());
        assert!(Q944_RESIDUAL_NON_HCLZ_ROWS.contains(&row));
        let ar: Vec<&QReg> = a[lo..hi].iter().collect();
        let br: Vec<&QReg> = b[lo..hi].iter().collect();
        strict_compare_gated_dirty_carry_refs(circ, &ar, &br, active, out, dirty_parity);
        circ.b.record_lowq_liveness_marker(format!(
            concat!(
                "q944_residual_dirty_compare=1;row={};substep={};",
                "carry=parity;compared_bits={};allocation_free=true;",
                "active_restored=true;carry_restored=true;operands_restored=true"
            ),
            row,
            substep.label(),
            hi - lo,
        ));
        return;
    }
    match q945_carry {
        Some(Q945NarrowCarry::Borrow {
            lane,
            host,
            row,
            substep,
            ..
        }) => {
            let ar: Vec<&QReg> = a[lo..hi].iter().collect();
            let br: Vec<&QReg> = b[lo..hi].iter().collect();
            borrow_compare_gated_refs_with_carry(circ, &ar, &br, active, out, lane);
            circ.b.record_lowq_liveness_marker(format!(
                concat!(
                    "q945_borrowed_carry=1;row={};substep={};host={};bit={};",
                    "compare=windowed;compared_bits={};restored=true;operand_disjoint=true"
                ),
                row,
                substep.label(),
                host.register.label(),
                host.bit,
                hi - lo,
            ));
        }
        Some(Q945NarrowCarry::Row364DivisionLower80 {
            carry, not_gate, ..
        }) => {
            assert_eq!(a.len(), 81, "Q945 row-364 division A width drift");
            assert_eq!(b.len(), 81, "Q945 row-364 division B width drift");
            assert!(std::ptr::eq(carry, &b[80]), "Q945 row-364 carry drift");
            assert!(
                std::ptr::eq(not_gate, &a[80]),
                "Q945 row-364 NOT gate drift"
            );
            let ar: Vec<&QReg> = a[..80].iter().collect();
            let br: Vec<&QReg> = b[..80].iter().collect();
            borrow_compare_gated_not_refs_with_carry(
                circ, &ar, &br, active, not_gate, out, carry,
            );
            circ.b.record_lowq_liveness_marker(
                concat!(
                    "q945_borrowed_carry=1;row=364;substep=division;host=B;bit=80;",
                    "compare=lower80;not_gate=A[80];restored=true;operand_disjoint=true"
                )
                .to_owned(),
            );
        }
        Some(Q945NarrowCarry::ResidualDirtyParity { .. }) => unreachable!(),
        None => {
            let ar: Vec<&QReg> = a[lo..hi].iter().collect();
            let br: Vec<&QReg> = b[lo..hi].iter().collect();
            borrow_compare_gated_refs(circ, &ar, &br, active, out);
        }
    }
}

#[derive(Clone, Copy)]
enum Q945ArithmeticOperation {
    Add,
    Sub,
}

impl Q945ArithmeticOperation {
    const fn label(self) -> &'static str {
        match self {
            Self::Add => "add",
            Self::Sub => "sub",
        }
    }

    const fn section(self) -> &'static str {
        match self {
            Self::Add => "p.add",
            Self::Sub => "p.sub",
        }
    }
}

fn q945_controlled_arithmetic(
    circ: &mut Circuit,
    operation: Q945ArithmeticOperation,
    gate: &QReg,
    a: &[&QReg],
    b: &[&QReg],
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::{
        ctrl_add, ctrl_sub,
    };

    let Some(context) = q945_carry.and_then(Q945NarrowCarry::dirty_parity_arithmetic) else {
        match operation {
            Q945ArithmeticOperation::Add => ctrl_add(circ, gate, a, b),
            Q945ArithmeticOperation::Sub => ctrl_sub(circ, gate, a, b),
        }
        return;
    };

    assert!(lowq_q945_dirty_parity_arithmetic_enabled());
    let residual = Q944_RESIDUAL_NON_HCLZ_ROWS.contains(&context.row);
    assert!(Q945_NON_HCLZ_ROWS.contains(&context.row) || residual);
    if residual {
        assert!(lowq_q944_residual_one_lane_cut_enabled());
    }
    assert_eq!(a.len(), b.len(), "Q945 dirty-parity operand width drift");
    let widths = super::q949_robust_envelope::q949_robust_pair_symmetric_widths(context.row);
    let expected_width = match context.substep {
        Q945Substep::Division => widths[0],
        Q945Substep::Multiply => widths[2],
    };
    assert_eq!(a.len(), expected_width, "Q945 dirty-parity route width drift");
    assert!(!std::ptr::eq(gate, context.lane));
    assert!(
        a.iter()
            .chain(b)
            .all(|lane| !std::ptr::eq(*lane, gate) && !std::ptr::eq(*lane, context.lane)),
        "Q945 dirty-parity carry/gate aliases an arithmetic operand"
    );

    let allocation_serial = circ.b.allocation_serial;
    let next_qubit = circ.b.next_qubit;
    let active_qubits = circ.b.active_qubits;
    let free_qubits = circ.b.free_qubits.clone();
    let section = circ.push_section(operation.section());
    match operation {
        Q945ArithmeticOperation::Add => {
            controlled_add_dirty_carry_refs(circ, gate, context.lane, a, b)
        }
        Q945ArithmeticOperation::Sub => {
            controlled_sub_dirty_carry_refs(circ, gate, context.lane, a, b)
        }
    }
    assert_eq!(circ.b.allocation_serial, allocation_serial);
    assert_eq!(circ.b.next_qubit, next_qubit);
    assert_eq!(circ.b.active_qubits, active_qubits);
    assert_eq!(circ.b.free_qubits, free_qubits);
    circ.b.record_lowq_liveness_marker(format!(
        concat!(
            "{}_dirty_parity_arithmetic=1;row={};substep={};operation={};width={};",
            "carry=parity;allocation_free=true;carry_restored=true;operand_disjoint=true;",
            "microkernel_commit={};microkernel_tree={};microkernel_blob={}"
        ),
        if residual { "q944_residual" } else { "q945" },
        context.row,
        context.substep.label(),
        operation.label(),
        expected_width,
        Q945_DIRTY_PARITY_MICROKERNEL_COMMIT,
        Q945_DIRTY_PARITY_MICROKERNEL_TREE,
        Q945_DIRTY_PARITY_MICROKERNEL_BLOB,
    ));
    circ.pop_section(&section);
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
enum Q944DivisionQuotientMode {
    Baseline,
    QuotientWitness,
}

#[allow(clippy::too_many_arguments)]
fn q944_division_narrow_lt_controlled(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    out: &QReg,
    active: &QReg,
    lo: usize,
    q945_carry: Option<Q945NarrowCarry<'_>>,
    _mode: Q944DivisionQuotientMode,
) {
    narrow_lt_controlled(circ, a, b, out, active, lo, q945_carry);
}

/// WINDOWED division substep: same as `division_substep_act` but the two clz
/// computations scan only the schedule's clz windows (`lo_a`/`lo_b` = window low
/// bounds for A/B) and the B<<s / restore rotates use `rot_bits` shift bits
/// (shift bound) instead of the full `s_rot` width. The offset-clean clz operates
/// on (A, `B_aligned`), both ~bitlen(A), so it reuses the A window (`lo_a`). For
/// in-schedule inputs this is gate-identical to `division_substep_act`.
#[allow(clippy::too_many_arguments)]
pub(crate) fn division_substep_windowed(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_div: &[QReg],
    s_rot: &[&QReg],
    offset: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    lo_a: usize,
    lo_b: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    division_substep_windowed_mode(
        circ,
        a,
        b,
        q_div,
        s_rot,
        offset,
        active,
        extra_lenders,
        lo_a,
        lo_b,
        rot_bits,
        ctz_bits,
        transcript_loans,
        q945_carry,
        Q944DivisionQuotientMode::Baseline,
    );
}

#[allow(clippy::too_many_arguments)]
fn division_substep_windowed_mode(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_div: &[QReg],
    s_rot: &[&QReg],
    offset: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    lo_a: usize,
    lo_b: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
    quotient_mode: Q944DivisionQuotientMode,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::ctrl_sub;
    let aref: Vec<&QReg> = a.iter().collect();
    let bref: Vec<&QReg> = b.iter().collect();
    let n_pad = q_div.len();
    let rb = rot_bits.min(s_rot.len());
    let w = s_rot.len();
    let off_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(q_div.iter())
        .chain(s_rot.iter().copied())
        .chain(extra_lenders.iter().copied())
        .collect();

    // diff = bitlen(A)-bitlen(B) (windowed _middle, folded into the clz's own pa);
    // mask s_rot = diff AND active.
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        lo_a,
        lo_b,
        Q945HclzForm::Update,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Update),
    ) {
        direct_bitlen_diff_update(
            circ,
            a,
            b,
            lo_a,
            lo_b,
            s_rot,
            active,
            offset,
            false,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_update(
            circ,
            a,
            b,
            lo_a,
            lo_b,
            s_rot,
            active,
            false,
            transcript_loans.update,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, lo_a, lo_b, |circ, diff| {
            for j in 0..w {
                circ.ccx(active, &diff[j], &s_rot[j]);
            }
        });
    }

    rotate_left(circ, b, &s_rot[0..rb]); // B <<= s if active (bounded rotator)

    // offset = active AND (A < B_aligned) -- narrowed (A,B_aligned share bitlen).
    if lowq_q958_gated_compare_enabled() {
        q944_division_narrow_lt_controlled(
            circ,
            a,
            b,
            offset,
            active,
            lo_a,
            q945_carry,
            quotient_mode,
        );
    } else {
        let or = circ.alloc_qreg("dg.offr");
        narrow_lt(circ, a, b, &or, lo_a);
        circ.ccx(active, &or, offset);
        narrow_lt(circ, a, b, &or, lo_a);
        circ.zero_and_free(or);
    }
    rotate_one_by_off(circ, b, active, offset, false, &off_lenders); // B >>= 1 if offset
    ctrl_dec_by_off(circ, active, offset, s_rot, &off_lenders); // s_rot -= 1 if offset => s_eff

    // clean offset via windowed _middle clz on (A, B_aligned) -> A window. The diff
    // lives in the clz's pa (this clz is the shrunken_pz_divide_forward peak section).
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        lo_a,
        lo_a,
        Q945HclzForm::Parity,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Parity),
    ) {
        direct_bitlen_diff_parity(circ, a, b, lo_a, lo_a, offset, active, extra_lenders);
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_parity(
            circ,
            a,
            b,
            lo_a,
            lo_a,
            offset,
            active,
            transcript_loans.parity,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, lo_a, lo_a, |circ, diff| {
            circ.ccx(active, &diff[0], offset);
        });
    }

    let demux_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(extra_lenders.iter().copied())
        .collect();
    if quotient_mode == Q944DivisionQuotientMode::QuotientWitness {
        q944_partial_demux_excluding_sentinel(circ, q_div, s_rot, active, &demux_lenders);
    }

    q945_controlled_arithmetic(
        circ,
        Q945ArithmeticOperation::Sub,
        active,
        &aref,
        &bref,
        q945_carry,
    ); // A -= B_aligned if active

    if quotient_mode == Q944DivisionQuotientMode::Baseline {
        set_bit_at_s_gated(circ, q_div, s_rot, active, offset, &demux_lenders);
    }

    rotate_right(circ, b, &s_rot[0..rb]); // restore B >>= s_eff (bounded rotator)

    if quotient_mode == Q944DivisionQuotientMode::Baseline {
        if lowq_exact_ctz_enabled() {
            let lenders: Vec<&QReg> = a
                .iter()
                .chain(b.iter())
                .chain(extra_lenders.iter().copied())
                .collect();
            exact_multihot_ctz_erase(
                circ,
                q_div,
                &s_rot[..ctz_bits.min(s_rot.len())],
                active,
                &lenders,
            );
        } else {
            let t = circ.alloc_qreg_bits("dg.ctz", w);
            xor_const(circ, &t, n_pad);
            let rev: Vec<&QReg> = q_div.iter().rev().collect();
            bit_length_lean(circ, &rev, &t, true);
            let srr = s_rot.to_vec();
            let tr: Vec<&QReg> = t.iter().collect();
            ctrl_sub(circ, active, &srr, &tr);
            bit_length_lean(circ, &rev, &t, false);
            xor_const(circ, &t, n_pad);
            for lane in t {
                circ.zero_and_free(lane);
            }
        }
    } else {
        // Clear the complete shift for non-sentinel quotients before returning
        // to the outer gate lifecycle. For s=24 only s[4:3] remain set, leaving
        // the comparator's s[0:1] scratch exactly clean.
        q944_clear_non_sentinel_shift(circ, q_div, s_rot);
    }
}

/// Gate-by-gate INVERSE of `division_substep_windowed` (for the backward pass).
/// Reverses the op sequence; the compute-use-uncompute blocks (clz-mask, offset,
/// offset-clean, q-demux) are self-inverse and run as-is; `rotate_left`<->right,
/// ctrl_sub->ctrl_add, ctrl_dec->ctrl_inc flip. Restores A += B<<`s_eff`, clears
/// the `q_div` bit, leaving `A/B/q_div/s/s_rot/offset` as before the forward step.
#[allow(clippy::too_many_arguments)]
pub(crate) fn division_substep_windowed_inv(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_div: &[QReg],
    s_rot: &[&QReg],
    offset: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    lo_a: usize,
    lo_b: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    division_substep_windowed_inv_mode(
        circ,
        a,
        b,
        q_div,
        s_rot,
        offset,
        active,
        extra_lenders,
        lo_a,
        lo_b,
        rot_bits,
        ctz_bits,
        transcript_loans,
        q945_carry,
        Q944DivisionQuotientMode::Baseline,
    );
}

#[allow(clippy::too_many_arguments)]
fn division_substep_windowed_inv_mode(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_div: &[QReg],
    s_rot: &[&QReg],
    offset: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    lo_a: usize,
    lo_b: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
    quotient_mode: Q944DivisionQuotientMode,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::ctrl_add;
    let aref: Vec<&QReg> = a.iter().collect();
    let bref: Vec<&QReg> = b.iter().collect();
    let n_pad = q_div.len();
    let rb = rot_bits.min(s_rot.len());
    let w = s_rot.len();
    let off_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(q_div.iter())
        .chain(s_rot.iter().copied())
        .chain(extra_lenders.iter().copied())
        .collect();

    // 12' reconstruct s_rot from the quotient witness. The quotient-host route
    // parked q[24] before the outer comparator and materializes other indices
    // only after the comparator has restored its low shift scratch.
    if quotient_mode == Q944DivisionQuotientMode::QuotientWitness {
        q944_reverse_materialize_non_sentinel_index(circ, q_div, s_rot);
    } else if lowq_exact_ctz_enabled() {
        let lenders: Vec<&QReg> = a
            .iter()
            .chain(b.iter())
            .chain(extra_lenders.iter().copied())
            .collect();
        exact_multihot_ctz_deposit(
            circ,
            q_div,
            &s_rot[..ctz_bits.min(s_rot.len())],
            active,
            &lenders,
        );
    } else {
        let t = circ.alloc_qreg_bits("dg.ctz", w);
        xor_const(circ, &t, n_pad);
        let rev: Vec<&QReg> = q_div.iter().rev().collect();
        bit_length_lean(circ, &rev, &t, true);
        let srr = s_rot.to_vec();
        let tr: Vec<&QReg> = t.iter().collect();
        ctrl_add(circ, active, &srr, &tr);
        bit_length_lean(circ, &rev, &t, false);
        xor_const(circ, &t, n_pad);
        for lane in t {
            circ.zero_and_free(lane);
        }
    }
    // 11' rotate_left (was rotate_right restore).
    rotate_left(circ, b, &s_rot[0..rb]);
    // 10' q_div demux (self-inverse XOR).
    let demux_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(extra_lenders.iter().copied())
        .collect();
    if quotient_mode == Q944DivisionQuotientMode::Baseline {
        set_bit_at_s_gated(circ, q_div, s_rot, active, offset, &demux_lenders);
    }
    // 9' ctrl_sub -> ctrl_add (restore A += B_aligned).
    q945_controlled_arithmetic(
        circ,
        Q945ArithmeticOperation::Add,
        active,
        &aref,
        &bref,
        q945_carry,
    );
    if quotient_mode == Q944DivisionQuotientMode::QuotientWitness {
        q944_partial_demux_excluding_sentinel(circ, q_div, s_rot, active, &demux_lenders);
    }
    // 8' offset clean (self-inverse, _middle); diff in the clz's pa.
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        lo_a,
        lo_a,
        Q945HclzForm::Parity,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Parity),
    ) {
        direct_bitlen_diff_parity(circ, a, b, lo_a, lo_a, offset, active, extra_lenders);
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_parity(
            circ,
            a,
            b,
            lo_a,
            lo_a,
            offset,
            active,
            transcript_loans.parity,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, lo_a, lo_a, |circ, diff| {
            circ.ccx(active, &diff[0], offset);
        });
    }
    // 7' ctrl_dec -> ctrl_inc.
    ctrl_inc_by_off(circ, active, offset, s_rot, &off_lenders);
    // 6' rotate_left (was rotate_right by offset).
    rotate_one_by_off(circ, b, active, offset, true, &off_lenders);
    // 5' offset compute (self-inverse) -- narrowed, same window as forward.
    if lowq_q958_gated_compare_enabled() {
        q944_division_narrow_lt_controlled(
            circ,
            a,
            b,
            offset,
            active,
            lo_a,
            q945_carry,
            quotient_mode,
        );
    } else {
        let or = circ.alloc_qreg("dg.offr");
        narrow_lt(circ, a, b, &or, lo_a);
        circ.ccx(active, &or, offset);
        narrow_lt(circ, a, b, &or, lo_a);
        circ.zero_and_free(or);
    }
    // 4' rotate_right (was rotate_left B<<s).
    rotate_right(circ, b, &s_rot[0..rb]);
    // 3',2',1' clz-mask block (self-inverse, _middle) -- clears s_rot to |0>.
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        lo_a,
        lo_b,
        Q945HclzForm::Update,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Update),
    ) {
        direct_bitlen_diff_update(
            circ,
            a,
            b,
            lo_a,
            lo_b,
            s_rot,
            active,
            offset,
            true,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_update(
            circ,
            a,
            b,
            lo_a,
            lo_b,
            s_rot,
            active,
            true,
            transcript_loans.update,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, lo_a, lo_b, |circ, diff| {
            for j in 0..w {
                circ.ccx(active, &diff[j], &s_rot[j]);
            }
        });
    }
}

/// `out ^= (reg != 0)` (restores reg).
fn or_nonzero(circ: &mut Circuit, reg: &[QReg], out: &QReg) {
    use crate::point_add::trailmix_port::arith::mcx::mcx_clean_k;
    let prev = circ.push_section("p.ornz");
    for q in reg {
        circ.x(q);
    }
    let refs: Vec<&QReg> = reg.iter().collect();
    mcx_clean_k(circ, &refs, out); // out ^= (reg == 0)
    for q in reg {
        circ.x(q);
    }
    circ.x(out); // out ^= (reg != 0)
    circ.pop_section(&prev);
}

/// `out ^= (reg == 0)` via X-bracket + mcx (clean, self-inverse, restores reg).
fn or_is_zero(circ: &mut Circuit, reg: &[QReg], out: &QReg) {
    use crate::point_add::trailmix_port::arith::mcx::mcx_clean_k;
    let prev = circ.push_section("p.orz");
    for q in reg {
        circ.x(q);
    }
    let refs: Vec<&QReg> = reg.iter().collect();
    mcx_clean_k(circ, &refs, out); // out ^= (reg == 0)
    for q in reg {
        circ.x(q);
    }
    circ.pop_section(&prev);
}

fn toggle_zero_dirty(
    circ: &mut Circuit,
    reg: &[QReg],
    out: &QReg,
    candidates: &[&QReg],
    action: &[&QReg],
) {
    for q in reg {
        circ.x(q);
    }
    let controls: Vec<&QReg> = reg.iter().collect();
    dirty_controlled_x(circ, &controls, out, candidates, action);
    for q in reg.iter().rev() {
        circ.x(q);
    }
}

fn toggle_nonzero_dirty(
    circ: &mut Circuit,
    reg: &[QReg],
    out: &QReg,
    candidates: &[&QReg],
    action: &[&QReg],
) {
    toggle_zero_dirty(circ, reg, out, candidates, action);
    circ.x(out);
}

#[allow(clippy::too_many_arguments)]
fn borrowed_swap_in_place(
    circ: &mut Circuit,
    aa: &[QReg],
    bb: &[QReg],
    cca: &[QReg],
    ccb: &[QReg],
    qq: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    off: &QReg,
) {
    assert!(s_rot.len() >= 2, "Q959 swap predicate lanes");
    let gate = if lowq_q956_off_borrow_enabled() {
        assert_q956_off_alias(off, counter, s_rot);
        assert!(!std::ptr::eq(off, parity), "Q956 off aliases parity");
        &s_rot[2]
    } else {
        off
    };
    let qz = &s_rot[0];
    let anz = &s_rot[1];
    let candidates: Vec<&QReg> = aa
        .iter()
        .chain(bb.iter())
        .chain(cca.iter())
        .chain(ccb.iter())
        .chain(qq.iter())
        .chain(counter.iter())
        .chain(s_rot.iter())
        .chain(std::iter::once(parity))
        .chain(std::iter::once(off))
        .collect();
    let action = [qz, anz, gate];
    let prev = circ.push_section("p.swap.borrowed");

    // At every step boundary s_rot is clean. Retain the two predicates in its
    // first lanes and materialize their active conjunction in a third lane on
    // Q956, leaving the conditionally-clean counter alias untouched.
    toggle_zero_dirty(circ, qq, qz, &candidates, &action);
    toggle_nonzero_dirty(circ, aa, anz, &candidates, &action);
    let toggle_gate = |circ: &mut Circuit| {
        for q in counter {
            circ.x(q);
        }
        let mut controls: Vec<&QReg> = counter.iter().collect();
        controls.push(qz);
        controls.push(anz);
        dirty_controlled_x(circ, &controls, gate, &candidates, &action);
        for q in counter.iter().rev() {
            circ.x(q);
        }
    };
    toggle_gate(circ);
    for j in 0..aa.len() {
        circ.cswap(gate, &aa[j], &bb[j]);
    }
    for j in 0..cca.len() {
        circ.cswap(gate, &cca[j], &ccb[j]);
    }
    circ.cx(gate, parity);
    toggle_gate(circ);
    toggle_nonzero_dirty(circ, aa, anz, &candidates, &action);
    toggle_zero_dirty(circ, qq, qz, &candidates, &action);
    circ.pop_section(&prev);
}

/// WINDOWED multiply substep: same as `multiply_substep_act` but the two clz
/// computations scan the schedule's cofactor clz windows. The `o` clz is on
/// (ca, cb<<s2), both ~bitlen(ca) -> ca window (`ca_window`). The s_rot-clean clz is
/// on (cb, ca) -> cb/ca windows. The cb<<s2 / restore rotates use `rot_bits`.
/// q (ctz) is small -> not windowed. Gate-identical for in-schedule inputs.
#[allow(clippy::too_many_arguments)]
pub(crate) fn multiply_substep_windowed(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_mul: &[QReg],
    s_rot: &[&QReg],
    off: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    ca_window: usize,
    cb_window: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::ctrl_add;
    let aref: Vec<&QReg> = a.iter().collect();
    let bref: Vec<&QReg> = b.iter().collect();
    let n_pad = q_mul.len();
    let rb = rot_bits.min(s_rot.len());
    let w = s_rot.len();
    let off_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(q_mul.iter())
        .chain(s_rot.iter().copied())
        .chain(extra_lenders.iter().copied())
        .collect();

    if lowq_exact_ctz_enabled() {
        let lenders: Vec<&QReg> = a
            .iter()
            .chain(b.iter())
            .chain(extra_lenders.iter().copied())
            .collect();
        exact_multihot_ctz_deposit(
            circ,
            q_mul,
            &s_rot[..ctz_bits.min(s_rot.len())],
            active,
            &lenders,
        );
    } else {
        let t = circ.alloc_qreg_bits("mg.ctz", w);
        let rev: Vec<&QReg> = q_mul.iter().rev().collect();
        xor_const(circ, &t, n_pad);
        bit_length_lean(circ, &rev, &t, true);
        for j in 0..w {
            circ.ccx(active, &t[j], &s_rot[j]);
        }
        bit_length_lean(circ, &rev, &t, false);
        xor_const(circ, &t, n_pad);
        for lane in t {
            circ.zero_and_free(lane);
        }
    }

    let demux_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(extra_lenders.iter().copied())
        .collect();
    set_bit_at_s_gated(circ, q_mul, s_rot, active, off, &demux_lenders);

    rotate_left(circ, b, &s_rot[0..rb]); // b <<= s if active (bounded rotator)
    q945_controlled_arithmetic(
        circ,
        Q945ArithmeticOperation::Add,
        active,
        &aref,
        &bref,
        q945_carry,
    ); // a += b<<s if active

    // o = active AND (bitlen(ca) != bitlen(cb<<s2)) -- ca window, _middle; diff in
    // the clz's pa. This clz is the shrunken_pz_divide_forward peak section.
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        ca_window,
        ca_window,
        Q945HclzForm::Parity,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Parity),
    ) {
        direct_bitlen_diff_parity(
            circ,
            a,
            b,
            ca_window,
            ca_window,
            off,
            active,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_parity(
            circ,
            a,
            b,
            ca_window,
            ca_window,
            off,
            active,
            transcript_loans.parity,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, ca_window, ca_window, |circ, diff| {
            circ.ccx(active, &diff[0], off);
        });
    }
    rotate_one_by_off(circ, b, active, off, true, &off_lenders); // b <<= 1 if o
    ctrl_inc_by_off(circ, active, off, s_rot, &off_lenders);
    if lowq_q958_gated_compare_enabled() {
        narrow_lt_controlled(circ, a, b, off, active, ca_window, q945_carry);
    } else {
        let lt = circ.alloc_qreg("mg.cleanlt");
        narrow_lt(circ, a, b, &lt, ca_window);
        circ.ccx(active, &lt, off);
        narrow_lt(circ, a, b, &lt, ca_window);
        circ.zero_and_free(lt);
    }
    rotate_right(circ, b, &s_rot[0..rb]); // restore b >>= s_eff (bounded rotator)

    // clean s_rot via _middle clz on (cb, ca): s_rot += (bitlen(cb)-bitlen(ca)).
    if selective_direct_bitlen_needed(
        circ,
        b,
        a,
        cb_window,
        ca_window,
        Q945HclzForm::Update,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Update),
    ) {
        direct_bitlen_diff_update(
            circ,
            b,
            a,
            cb_window,
            ca_window,
            s_rot,
            active,
            off,
            false,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_update(
            circ,
            b,
            a,
            cb_window,
            ca_window,
            s_rot,
            active,
            false,
            transcript_loans.update,
        );
    } else {
        clz_diff_body_middle(circ, b, a, w, cb_window, ca_window, |circ, diff| {
            let srr = s_rot.to_vec();
            let ter: Vec<&QReg> = diff.iter().collect();
            ctrl_add(circ, active, &srr, &ter);
        });
    }
}

/// Gate-by-gate INVERSE of `multiply_substep_windowed` (backward pass). Reverses
/// the sequence; clz/o/q-demux blocks are self-inverse; `rotate_left`<->right,
/// ctrl_add->ctrl_sub, ctrl_inc->ctrl_dec flip. Restores ca -= cb<<s2, re-sets
/// the `q_mul` bit.
#[allow(clippy::too_many_arguments)]
pub(crate) fn multiply_substep_windowed_inv(
    circ: &mut Circuit,
    a: &[QReg],
    b: &[QReg],
    q_mul: &[QReg],
    s_rot: &[&QReg],
    off: &QReg,
    active: &QReg,
    extra_lenders: &[&QReg],
    ca_window: usize,
    cb_window: usize,
    rot_bits: usize,
    ctz_bits: usize,
    transcript_loans: BorrowedTranscriptLoans<'_>,
    q945_carry: Option<Q945NarrowCarry<'_>>,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_primitives::{ctrl_add, ctrl_sub};
    let aref: Vec<&QReg> = a.iter().collect();
    let bref: Vec<&QReg> = b.iter().collect();
    let n_pad = q_mul.len();
    let rb = rot_bits.min(s_rot.len());
    let w = s_rot.len();
    let _ = ctrl_add;
    let off_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(q_mul.iter())
        .chain(s_rot.iter().copied())
        .chain(extra_lenders.iter().copied())
        .collect();

    // 10' s_rot clean inverse: ctrl_add -> ctrl_sub (_middle); diff in the clz's pa.
    if selective_direct_bitlen_needed(
        circ,
        b,
        a,
        cb_window,
        ca_window,
        Q945HclzForm::Update,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Update),
    ) {
        direct_bitlen_diff_update(
            circ,
            b,
            a,
            cb_window,
            ca_window,
            s_rot,
            active,
            off,
            true,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_update(
            circ,
            b,
            a,
            cb_window,
            ca_window,
            s_rot,
            active,
            true,
            transcript_loans.update,
        );
    } else {
        clz_diff_body_middle(circ, b, a, w, cb_window, ca_window, |circ, diff| {
            let srr = s_rot.to_vec();
            let ter: Vec<&QReg> = diff.iter().collect();
            ctrl_sub(circ, active, &srr, &ter);
        });
    }
    // 9' rotate_left (was rotate_right restore).
    rotate_left(circ, b, &s_rot[0..rb]);
    // 8' clean-o block (self-inverse) -- narrowed, same window as forward.
    if lowq_q958_gated_compare_enabled() {
        narrow_lt_controlled(circ, a, b, off, active, ca_window, q945_carry);
    } else {
        let lt = circ.alloc_qreg("mg.cleanlt");
        narrow_lt(circ, a, b, &lt, ca_window);
        circ.ccx(active, &lt, off);
        narrow_lt(circ, a, b, &lt, ca_window);
        circ.zero_and_free(lt);
    }
    // 7' ctrl_inc -> ctrl_dec.
    ctrl_dec_by_off(circ, active, off, s_rot, &off_lenders);
    // 6' rotate_right (was rotate_left by o).
    rotate_one_by_off(circ, b, active, off, false, &off_lenders);
    // 5' o clz block (self-inverse, _middle); diff in the clz's pa.
    if selective_direct_bitlen_needed(
        circ,
        a,
        b,
        ca_window,
        ca_window,
        Q945HclzForm::Parity,
        transcript_loans.q945_local_borrowed(Q945HclzForm::Parity),
    ) {
        direct_bitlen_diff_parity(
            circ,
            a,
            b,
            ca_window,
            ca_window,
            off,
            active,
            extra_lenders,
        );
    } else if lowq_hybrid_clz_enabled() {
        hybrid_bitlen_diff_parity(
            circ,
            a,
            b,
            ca_window,
            ca_window,
            off,
            active,
            transcript_loans.parity,
        );
    } else {
        clz_diff_body_middle(circ, a, b, w, ca_window, ca_window, |circ, diff| {
            circ.ccx(active, &diff[0], off);
        });
    }
    // 4' ctrl_add -> ctrl_sub (undo ca += cb<<s2).
    q945_controlled_arithmetic(
        circ,
        Q945ArithmeticOperation::Sub,
        active,
        &aref,
        &bref,
        q945_carry,
    );
    // 3' rotate_right (was rotate_left cb<<s2).
    rotate_right(circ, b, &s_rot[0..rb]);
    // 2' q_mul clear demux (self-inverse).
    let demux_lenders: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(extra_lenders.iter().copied())
        .collect();
    set_bit_at_s_gated(circ, q_mul, s_rot, active, off, &demux_lenders);
    // 1' clear the least-significant-set-bit index from s_rot.
    if lowq_exact_ctz_enabled() {
        let lenders: Vec<&QReg> = a
            .iter()
            .chain(b.iter())
            .chain(extra_lenders.iter().copied())
            .collect();
        exact_multihot_ctz_erase(
            circ,
            q_mul,
            &s_rot[..ctz_bits.min(s_rot.len())],
            active,
            &lenders,
        );
    } else {
        let t = circ.alloc_qreg_bits("mg.ctz", w);
        let rev: Vec<&QReg> = q_mul.iter().rev().collect();
        xor_const(circ, &t, n_pad);
        bit_length_lean(circ, &rev, &t, true);
        for j in 0..w {
            circ.ccx(active, &t[j], &s_rot[j]);
        }
        bit_length_lean(circ, &rev, &t, false);
        xor_const(circ, &t, n_pad);
        for lane in t {
            circ.zero_and_free(lane);
        }
    }
}

// NEXT (reversible_pz_notes.md has the primitive mapping):
//   fn normalize_input(circ, x, sgn)               -- x -> min(x,P-x), set sgn
//   fn division_substep(circ, regs, flags, s, bound)
//   fn multiply_substep(circ, regs, flags, s, bound)
//   fn transition(circ, regs, flags)
//   fn iterate(circ, regs, flags, n_iters)         -- the fixed-count driver
//   fn recover_inverse(circ, regs, flags)          -- parity^sgn sign fix
//   test pz_sm_faithful  -- per-iter contract vs a Rust port of pz_big_step

// ===== shrunken_pz reversible inversion step driver (shared fwd/back, used by
// the round-trip test AND the EC-add) =====

// ---- shared forward/backward step helpers (used by the round-trip) ----

/// Compute `g = active AND (x < y)` directly from the comparator carry, run the
/// gated body, then clear `g` with the same restored-input comparison. No
/// separate `(x < y)` lane is retained across the body.
pub(crate) fn gate_hold(
    c: &mut Circuit,
    x: &[QReg],
    y: &[QReg],
    active: &QReg,
    g: &QReg,
    borrowed_carry: Option<&QReg>,
    body: impl FnOnce(&mut Circuit, &QReg),
) {
    let xr: Vec<&QReg> = x.iter().collect();
    let yr: Vec<&QReg> = y.iter().collect();
    let compare = |c: &mut Circuit| {
        if let Some(carry) = borrowed_carry {
            borrow_compare_gated_refs_with_carry(c, &xr, &yr, active, g, carry);
        } else {
            borrow_compare_gated_refs(c, &xr, &yr, active, g);
        }
    };
    compare(c);
    body(c, g);
    compare(c);
}

/// Run a gated body with `g = (counter == 0) AND (x < y)` while allocating
/// only `g`. The existing parity lane temporarily hosts the active predicate;
/// its prior value is parked in `g`, swapped back before the body, and restored
/// exactly after the second comparison. Two clean shift lanes host the
/// comparator output and carry only while the body is not running.
#[allow(clippy::too_many_arguments)]
fn gate_hold_counter_zero(
    c: &mut Circuit,
    x: &[QReg],
    y: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    g: &QReg,
    candidates: &[&QReg],
    body: impl FnOnce(&mut Circuit, &QReg),
) {
    assert!(s_rot.len() >= 2, "Q959 comparator borrow lanes");
    let lt = &s_rot[0];
    let carry = &s_rot[1];
    let action = [g, parity, lt, carry];
    let xr: Vec<&QReg> = x.iter().collect();
    let yr: Vec<&QReg> = y.iter().collect();

    let swap_parity_gate = |c: &mut Circuit| {
        c.cx(parity, g);
        c.cx(g, parity);
        c.cx(parity, g);
    };
    let toggle_active = |c: &mut Circuit| {
        if counter.is_empty() {
            c.x(parity);
        } else {
            toggle_zero_dirty(c, counter, parity, candidates, &action);
        }
    };
    let compare = |c: &mut Circuit| {
        borrow_compare_refs_with_carry(c, &xr, &yr, lt, carry);
    };
    let remove_nonless_active = |c: &mut Circuit| {
        for q in counter {
            c.x(q);
        }
        c.x(lt);
        let mut controls: Vec<&QReg> = counter.iter().collect();
        controls.push(lt);
        dirty_controlled_x(c, &controls, g, candidates, &action);
        c.x(lt);
        for q in counter.iter().rev() {
            c.x(q);
        }
    };

    let compute_allocation_serial = c.b.allocation_serial;
    let lifecycle_active_qubits = c.b.active_qubits;

    // Park P in g, clear parity, compute active in parity, then swap the two:
    // parity=P and g=active. Remove the active-and-not-less branch to obtain
    // g=active-and-less.
    c.cx(parity, g);
    c.cx(g, parity);
    toggle_active(c);
    swap_parity_gate(c);
    compare(c);
    remove_nonless_active(c);
    compare(c);

    assert_eq!(c.b.allocation_serial, compute_allocation_serial);
    assert_eq!(c.b.active_qubits, lifecycle_active_qubits);
    body(c, g);
    assert_eq!(c.b.active_qubits, lifecycle_active_qubits);

    // Exact reverse of the preparation above.
    let uncompute_allocation_serial = c.b.allocation_serial;
    compare(c);
    remove_nonless_active(c);
    compare(c);
    swap_parity_gate(c);
    toggle_active(c);
    c.cx(g, parity);
    c.cx(parity, g);
    assert_eq!(c.b.allocation_serial, uncompute_allocation_serial);
    assert_eq!(c.b.active_qubits, lifecycle_active_qubits);
}

#[allow(clippy::too_many_arguments)]
fn q944_gate_hold_counter_zero_hosted(
    c: &mut Circuit,
    x: &[QReg],
    y: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    row: usize,
    substep: Q945Substep,
    inverse: bool,
    host: Q945Host,
    peer: Q945Host,
    host_lane: &QReg,
    peer_lane: &QReg,
    body: impl FnOnce(&mut Circuit, &QReg),
) {
    assert!(lowq_q944_full_structural_enabled());
    assert_eq!(q944_full_gate_route(row, substep), Q944FullGateRoute::Ordinary { host, peer });
    assert_eq!(counter.len(), 1, "Q944 hosted gate requires the affine done lane");
    assert_eq!(x.len(), y.len());
    assert_eq!(host.bit, peer.bit);
    assert!(host.bit < x.len());
    assert!(!std::ptr::eq(host_lane, peer_lane));
    assert!(!std::ptr::eq(host_lane, parity));
    assert!(!std::ptr::eq(peer_lane, parity));

    let host_in_x = std::ptr::eq(host_lane, &x[host.bit]);
    let host_in_y = std::ptr::eq(host_lane, &y[host.bit]);
    let peer_in_x = std::ptr::eq(peer_lane, &x[peer.bit]);
    let peer_in_y = std::ptr::eq(peer_lane, &y[peer.bit]);
    assert_eq!(usize::from(host_in_x) + usize::from(host_in_y), 1);
    assert_eq!(usize::from(peer_in_x) + usize::from(peer_in_y), 1);
    assert!(host_in_x == peer_in_y && host_in_y == peer_in_x);

    let xr: Vec<&QReg> = x
        .iter()
        .enumerate()
        .filter_map(|(bit, lane)| (bit != host.bit).then_some(lane))
        .collect();
    let yr: Vec<&QReg> = y
        .iter()
        .enumerate()
        .filter_map(|(bit, lane)| (bit != host.bit).then_some(lane))
        .collect();
    let toggle_gate = |c: &mut Circuit| {
        c.x(&counter[0]);
        strict_compare_gated_dirty_carry_refs(
            c,
            &xr,
            &yr,
            &counter[0],
            host_lane,
            parity,
        );
        c.x(&counter[0]);
    };

    let entry_active = c.b.active_qubits;
    let compute_serial = c.b.allocation_serial;
    let entry_next_qubit = c.b.next_qubit;
    let compute_free = c.b.free_qubits.clone();
    toggle_gate(c);
    assert_eq!(c.b.allocation_serial, compute_serial);
    assert_eq!(c.b.active_qubits, entry_active);
    assert_eq!(c.b.free_qubits, compute_free);

    body(c, host_lane);
    assert_eq!(c.b.allocation_serial, compute_serial);
    assert_eq!(c.b.next_qubit, entry_next_qubit);
    assert_eq!(c.b.free_qubits, compute_free);
    assert_eq!(c.b.active_qubits, entry_active);

    let uncompute_serial = c.b.allocation_serial;
    let uncompute_free = c.b.free_qubits.clone();
    toggle_gate(c);
    assert_eq!(c.b.allocation_serial, uncompute_serial);
    assert_eq!(c.b.active_qubits, entry_active);
    assert_eq!(c.b.free_qubits, uncompute_free);
    c.b.record_lowq_liveness_marker(format!(
        concat!(
            "q944_full_gate_host=1;row={};substep={};host={};bit={};",
            "direction={};",
            "peer={};peer_bit={};host_physical={};peer_physical={};",
            "omitted_equal_zero_pair=true;compute_allocation_free=true;",
            "uncompute_allocation_free=true;entry_active={};exit_active={};",
            "entry_allocation_serial={};exit_allocation_serial={};",
            "entry_next_qubit={};exit_next_qubit={};free_list_restored=true;",
            "host_restored_zero=true;peer_restored_zero=true;",
            "forward_reverse_symmetric=true;phase_clean=true;ancilla_clean=true;",
            "census_commit={};census_tree={};census_job={}"
        ),
        row,
        substep.label(),
        host.register.label(),
        host.bit,
        if inverse { "reverse" } else { "forward" },
        peer.register.label(),
        peer.bit,
        host_lane.id(),
        peer_lane.id(),
        entry_active,
        c.b.active_qubits,
        compute_serial,
        c.b.allocation_serial,
        entry_next_qubit,
        c.b.next_qubit,
        Q944_GATE_HOST_CENSUS_COMMIT,
        Q944_GATE_HOST_CENSUS_TREE,
        Q944_GATE_HOST_CENSUS_JOB,
    ));
}

#[allow(clippy::too_many_arguments)]
fn q944_gate_hold_quotient_witness(
    c: &mut Circuit,
    x: &[QReg],
    y: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    q: &[QReg],
    s_rot: &[QReg],
    boundary_candidates: &[&QReg],
    row: usize,
    inverse: bool,
    body: impl FnOnce(&mut Circuit, &QReg),
) {
    assert!(lowq_q944_full_structural_enabled());
    assert_eq!(
        q944_full_gate_route(row, Q945Substep::Division),
        Q944FullGateRoute::QuotientWitness
    );
    assert_eq!(q.len(), Q944_QUOTIENT_WIDTH);
    assert_eq!(s_rot.len(), Q944_SHIFT_WIDTH);
    let s_refs: Vec<&QReg> = s_rot.iter().collect();
    let host = &q[Q944_QUOTIENT_SENTINEL];
    let entry_active = c.b.active_qubits;
    let handoff_serial = c.b.allocation_serial;
    let entry_next_qubit = c.b.next_qubit;
    let entry_free = c.b.free_qubits.clone();
    if inverse {
        q944_reverse_park_sentinel(c, q, &s_refs);
    }
    assert_eq!(c.b.allocation_serial, handoff_serial);
    assert_eq!(c.b.active_qubits, entry_active);

    gate_hold_counter_zero(
        c,
        x,
        y,
        counter,
        parity,
        s_rot,
        host,
        boundary_candidates,
        body,
    );
    assert_eq!(c.b.allocation_serial, handoff_serial);
    assert_eq!(c.b.next_qubit, entry_next_qubit);
    assert_eq!(c.b.free_qubits, entry_free);
    if !inverse {
        let commit_serial = c.b.allocation_serial;
        q944_commit_parked_sentinel(c, q, &s_refs);
        assert_eq!(c.b.allocation_serial, commit_serial);
    }
    assert_eq!(c.b.allocation_serial, handoff_serial);
    assert_eq!(c.b.next_qubit, entry_next_qubit);
    assert_eq!(c.b.free_qubits, entry_free);
    assert_eq!(c.b.active_qubits, entry_active);
    c.b.record_lowq_liveness_marker(format!(
        concat!(
            "q944_full_quotient_witness=1;row={};substep=division;",
            "direction={};host=q;bit=24;host_physical={};sentinel=24;",
            "park=s[4:3];gate_scratch=s[1:0];partial_demux_before_arithmetic=true;",
            "reverse_park={};reverse_erasure={};forward_commit={};",
            "handoff_allocation_free=true;entry_active={};exit_active={};",
            "entry_allocation_serial={};exit_allocation_serial={};",
            "entry_next_qubit={};exit_next_qubit={};free_list_restored=true;",
            "phase_clean=true;ancilla_clean=true;witness_commit={};",
            "witness_tree={};witness_blob={};witness_job={}"
        ),
        row,
        if inverse { "reverse" } else { "forward" },
        host.id(),
        inverse,
        inverse,
        !inverse,
        entry_active,
        c.b.active_qubits,
        handoff_serial,
        c.b.allocation_serial,
        entry_next_qubit,
        c.b.next_qubit,
        Q944_QUOTIENT_WITNESS_COMMIT,
        Q944_QUOTIENT_WITNESS_TREE,
        Q944_QUOTIENT_WITNESS_BLOB,
        Q944_QUOTIENT_WITNESS_JOB,
    ));
}

#[allow(clippy::too_many_arguments)]
fn q944_run_full_gate(
    c: &mut Circuit,
    row: usize,
    substep: Q945Substep,
    inverse: bool,
    x: &[QReg],
    y: &[QReg],
    aa: &[QReg],
    bb: &[QReg],
    cca: &[QReg],
    ccb: &[QReg],
    qq: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    off: &QReg,
    boundary_candidates: &[&QReg],
    body: impl FnOnce(&mut Circuit, &QReg),
) {
    match q944_full_gate_route(row, substep) {
        Q944FullGateRoute::Ordinary { host, peer } => {
            let host_lane = q945_host_lane(host, aa, bb, cca, ccb, qq, off);
            let peer_lane = q945_host_lane(peer, aa, bb, cca, ccb, qq, off);
            q944_gate_hold_counter_zero_hosted(
                c,
                x,
                y,
                counter,
                parity,
                row,
                substep,
                inverse,
                host,
                peer,
                host_lane,
                peer_lane,
                body,
            );
        }
        Q944FullGateRoute::QuotientWitness => {
            assert_eq!(substep, Q945Substep::Division);
            q944_gate_hold_quotient_witness(
                c,
                x,
                y,
                counter,
                parity,
                qq,
                s_rot,
                boundary_candidates,
                row,
                inverse,
                body,
            );
        }
    }
}

/// done-counter (forward: counter += conv) / its inverse (counter -= conv),
/// conv = (A==0 & q==0). `done` is clean scratch (|0> at exit). User's recipe.
pub(crate) fn done_counter_fn(
    c: &mut Circuit,
    aa: &[QReg],
    qq: &[QReg],
    counter: &[QReg],
    s_rot: &[QReg],
    off: &QReg,
    candidates: &[&QReg],
    inverse: bool,
) {
    if counter.is_empty() {
        return;
    }
    if lowq_q959_selective_borrow_enabled() {
        assert!(s_rot.len() >= 2, "Q959 done predicate lanes");
        let done = if lowq_q956_off_borrow_enabled() {
            // Boundary logic gets a truly clean lane; counter[0] is reserved
            // for conditionally-clean borrowing only inside active bodies.
            assert_q956_off_alias(off, counter, s_rot);
            &s_rot[2]
        } else {
            off
        };
        let az = &s_rot[0];
        let qz = &s_rot[1];
        let counter_refs: Vec<&QReg> = counter.iter().collect();
        let action = [done, az, qz];
        let conv = |c: &mut Circuit| {
            toggle_zero_dirty(c, aa, az, candidates, &action);
            toggle_zero_dirty(c, qq, qz, candidates, &action);
            c.ccx(az, qz, done);
            toggle_zero_dirty(c, qq, qz, candidates, &action);
            toggle_zero_dirty(c, aa, az, candidates, &action);
        };
        let cnz = |c: &mut Circuit| {
            toggle_nonzero_dirty(c, counter, az, candidates, &action);
            c.cx(az, done);
            toggle_nonzero_dirty(c, counter, az, candidates, &action);
        };
        if inverse {
            cnz(c);
            dirty_controlled_inc_suffix(c, &[done], &counter_refs, 0, true, candidates);
            conv(c);
        } else {
            conv(c);
            dirty_controlled_inc_suffix(c, &[done], &counter_refs, 0, false, candidates);
            cnz(c);
        }
        return;
    }

    let done = c.alloc_qreg("done");
    let conv = |c: &mut Circuit, done: &QReg| {
        let az = c.alloc_qreg("d.az");
        let qz = c.alloc_qreg("d.qz");
        or_is_zero(c, aa, &az);
        or_is_zero(c, qq, &qz);
        c.ccx(&az, &qz, done); // done ^= (A==0 & q==0)
        or_is_zero(c, qq, &qz);
        or_is_zero(c, aa, &az);
        c.zero_and_free(qz);
        c.zero_and_free(az);
    };
    let cnz = |c: &mut Circuit, done: &QReg| {
        let z = c.alloc_qreg("d.cnz");
        or_nonzero(c, counter, &z);
        c.cx(&z, done); // done ^= (counter != 0)
        or_nonzero(c, counter, &z);
        c.zero_and_free(z);
    };
    if inverse {
        cnz(c, &done);
        ctrl_dec(c, &done, counter);
        conv(c, &done);
    } else {
        conv(c, &done);
        ctrl_inc(c, &done, counter);
        cnz(c, &done);
    }
    c.zero_and_free(done);
}

const Q949_AFFINE_COUNTER_WIDTH: usize = 8;
const Q949_FIRST_TERMINAL_ROW: usize = 371;
const SECP256K1_P_LOW_BYTE: usize = 0x2f;

const BORROWED_ROW_379: usize = 379;
const BORROWED_ROW_380: usize = 380;
const BORROWED_ROW_379_TRANSIENT_A_BITS: usize = 71;
const BORROWED_ROW_380_FORWARD_CB_BITS: usize = 255;

fn assert_borrowed_transcript_lender_certificate() {
    use super::q949_robust_envelope::{
        q949_robust_envelope_sha256, q949_robust_pair_symmetric_widths,
        q949_robust_phase_requirements, q949_robust_row_requirements,
        Q949RobustPhaseRequirement, Q949_ROBUST_ENVELOPE_SHA256,
    };
    use std::sync::OnceLock;

    static CHECKED: OnceLock<()> = OnceLock::new();
    CHECKED.get_or_init(|| {
        assert_eq!(
            q949_robust_envelope_sha256(),
            Q949_ROBUST_ENVELOPE_SHA256,
            "Borrowed transcript lender certificate envelope digest drift"
        );
        assert_eq!(
            q949_robust_row_requirements(BORROWED_ROW_379),
            [72, 72, 256, 256, 25],
            "Borrowed transcript row-379 support projection drift"
        );
        assert_eq!(
            q949_robust_pair_symmetric_widths(BORROWED_ROW_379),
            [72, 72, 256, 256, 25],
            "Borrowed transcript row-379 allocation drift"
        );
        assert_eq!(
            q949_robust_phase_requirements(
                BORROWED_ROW_379,
                Q949RobustPhaseRequirement::ForwardTransient,
            ),
            Some([71, 72, 256, 256, 25]),
            "Borrowed transcript row-379 transient support drift"
        );
        assert_eq!(
            q949_robust_row_requirements(BORROWED_ROW_380),
            [72, 72, 256, 255, 25],
            "Borrowed transcript row-380 support projection drift"
        );
        assert_eq!(
            q949_robust_pair_symmetric_widths(BORROWED_ROW_380),
            [72, 72, 256, 256, 25],
            "Borrowed transcript row-380 allocation drift"
        );
        assert_eq!(
            q949_robust_phase_requirements(
                BORROWED_ROW_380,
                Q949RobustPhaseRequirement::ForwardEntry,
            ),
            Some([72, 70, 256, 255, 25]),
            "Borrowed transcript row-380 forward-entry support drift"
        );
        assert_eq!(BORROWED_ROW_379_TRANSIENT_A_BITS, 71);
        assert_eq!(BORROWED_ROW_380_FORWARD_CB_BITS, 255);
    });
}

/// Select a loan only at a schedule point with an explicit zero certificate.
/// Rows before 371 have not entered terminal counting, so `counter[0]=0`.
/// Row 379 multiply has transient `A < 2^71`; row 380 division has a zero
/// cofactor top lane `cb[255]` in the forward direction. At reverse row 380,
/// `ca[255]` is usable only after normalizing the exact schedule relation
/// `ca[255] = NOT(active AND ca<cb)` with the live division predicate.
fn borrowed_transcript_loan<'a>(
    row: usize,
    inverse: bool,
    substep: BorrowedTranscriptSubstep,
    aa: &'a [QReg],
    cca: &'a [QReg],
    ccb: &'a [QReg],
    counter: &'a [QReg],
    relation_control: Option<&'a QReg>,
) -> Option<BorrowedTranscriptLoan<'a>> {
    if !lowq_borrowed_transcript_experiment_enabled() {
        return None;
    }
    assert_borrowed_transcript_lender_certificate();

    let (lane, kind, preparation) = if row < Q949_FIRST_TERMINAL_ROW {
        if q946_second_ownership_release_requested() {
            // The affine done lane is also the active-masked off selector on
            // Q946, so it cannot simultaneously be a transcript operand.
            // Own the seventh transcript lane at these slack sites instead.
            return None;
        }
        assert_eq!(
            counter.len(),
            1,
            "borrowed transcript preterminal counter ownership drift"
        );
        (
            &counter[0],
            BorrowedTranscriptLoanKind::PreterminalCounter,
            BorrowedTranscriptPreparation::AlreadyZero,
        )
    } else if row == BORROWED_ROW_379 && substep == BorrowedTranscriptSubstep::Multiply {
        assert_eq!(aa.len(), 72, "borrowed transcript row-379 A allocation drift");
        assert!(
            BORROWED_ROW_379_TRANSIENT_A_BITS <= 71,
            "borrowed transcript row-379 A[71] is not above the transient support"
        );
        (
            &aa[71],
            BorrowedTranscriptLoanKind::Row379AHigh,
            BorrowedTranscriptPreparation::AlreadyZero,
        )
    } else if row == BORROWED_ROW_380 && substep == BorrowedTranscriptSubstep::Division {
        assert_eq!(cca.len(), 256, "borrowed transcript row-380 ca allocation drift");
        assert_eq!(ccb.len(), 256, "borrowed transcript row-380 cb allocation drift");
        if inverse {
            if !lowq_reverse_ca255_relational_loan_enabled() {
                return None;
            }
            let control = relation_control
                .expect("reverse ca[255] relational loan requires the live division predicate");
            (
                &cca[255],
                BorrowedTranscriptLoanKind::Row380ReverseCaHigh,
                BorrowedTranscriptPreparation::ComplementOf(control),
            )
        } else {
            assert!(
                BORROWED_ROW_380_FORWARD_CB_BITS <= 255,
                "borrowed transcript forward row-380 cb[255] is not above support"
            );
            (
                &ccb[255],
                BorrowedTranscriptLoanKind::Row380ForwardCbHigh,
                BorrowedTranscriptPreparation::AlreadyZero,
            )
        }
    } else {
        return None;
    };

    Some(BorrowedTranscriptLoan {
        lane,
        kind,
        row,
        inverse,
        substep,
        preparation,
    })
}

#[allow(clippy::too_many_arguments)]
fn q945_host_lane<'a>(
    host: Q945Host,
    aa: &'a [QReg],
    bb: &'a [QReg],
    cca: &'a [QReg],
    ccb: &'a [QReg],
    qq: &'a [QReg],
    off: &'a QReg,
) -> &'a QReg {
    let register = match host.register {
        Q945StateRegister::A => aa,
        Q945StateRegister::B => bb,
        Q945StateRegister::Ca => cca,
        Q945StateRegister::Cb => ccb,
        Q945StateRegister::Q => qq,
        Q945StateRegister::CounterOff => {
            assert_eq!(host.bit, 0, "Q945 counter/off host bit drift");
            return off;
        }
    };
    register.get(host.bit).unwrap_or_else(|| {
        panic!(
            "Q945 host {}[{}] is outside its live allocation {}",
            host.register.label(),
            host.bit,
            register.len()
        )
    })
}

#[allow(clippy::too_many_arguments)]
fn q945_local_hclz_loans<'a>(
    row: usize,
    inverse: bool,
    substep: BorrowedTranscriptSubstep,
    aa: &'a [QReg],
    bb: &'a [QReg],
    cca: &'a [QReg],
    ccb: &'a [QReg],
    qq: &'a [QReg],
    counter: &'a [QReg],
    off: &'a QReg,
) -> Option<BorrowedTranscriptLoans<'a>> {
    if !Q945_HCLZ_ROWS.contains(&row) || !lowq_q945_local_hosts_enabled() {
        return None;
    }
    assert_eq!(counter.len(), 1, "Q945 requires the affine done lane");
    assert!(std::ptr::eq(off, &counter[0]), "Q945 off alias drift");
    let table_substep = match substep {
        BorrowedTranscriptSubstep::Division => Q945Substep::Division,
        BorrowedTranscriptSubstep::Multiply => Q945Substep::Multiply,
    };
    let make = |form| match q945_hclz_route(row, table_substep, form) {
        Q945HclzRoute::Borrow(host) => Some(BorrowedTranscriptLoan {
            lane: q945_host_lane(host, aa, bb, cca, ccb, qq, off),
            kind: BorrowedTranscriptLoanKind::Q945LocalHost(host, form),
            row,
            inverse,
            substep,
            preparation: BorrowedTranscriptPreparation::AlreadyZero,
        }),
        Q945HclzRoute::Direct => None,
    };
    Some(BorrowedTranscriptLoans {
        update: make(Q945HclzForm::Update),
        parity: make(Q945HclzForm::Parity),
        q945_local_class: true,
    })
}

#[allow(clippy::too_many_arguments)]
fn q945_narrow_carry<'a>(
    row: usize,
    substep: Q945Substep,
    aa: &'a [QReg],
    bb: &'a [QReg],
    cca: &'a [QReg],
    ccb: &'a [QReg],
    qq: &'a [QReg],
    off: &'a QReg,
    parity: &'a QReg,
) -> Option<Q945NarrowCarry<'a>> {
    if lowq_q944_residual_one_lane_cut_enabled()
        && Q944_RESIDUAL_NON_HCLZ_ROWS.contains(&row)
    {
        return Some(Q945NarrowCarry::ResidualDirtyParity {
            dirty_parity: parity,
            row,
            substep,
        });
    }
    if !Q945_NON_HCLZ_ROWS.contains(&row) || !lowq_q945_local_hosts_enabled() {
        return None;
    }
    let dirty_parity = lowq_q945_dirty_parity_arithmetic_enabled().then_some(parity);
    match q945_carry_route(row, substep) {
        Q945CarryRoute::Borrow(host) => Some(Q945NarrowCarry::Borrow {
            lane: q945_host_lane(host, aa, bb, cca, ccb, qq, off),
            dirty_parity,
            host,
            row,
            substep,
        }),
        Q945CarryRoute::Row364DivisionLower80 { carry, not_gate } => {
            assert_eq!((row, substep), (364, Q945Substep::Division));
            Some(Q945NarrowCarry::Row364DivisionLower80 {
                carry: q945_host_lane(carry, aa, bb, cca, ccb, qq, off),
                not_gate: q945_host_lane(not_gate, aa, bb, cca, ccb, qq, off),
                dirty_parity,
                row,
                substep,
            })
        }
    }
}

fn q949_bracket_affine_count(c: &mut Circuit, ca: &[QReg]) {
    assert!(
        ca.len() >= Q949_AFFINE_COUNTER_WIDTH,
        "Q949 affine counter carrier is narrower than one byte"
    );
    for (bit, lane) in ca[..Q949_AFFINE_COUNTER_WIDTH].iter().enumerate() {
        if (SECP256K1_P_LOW_BYTE >> bit) & 1 == 1 {
            c.x(lane);
        }
    }
}

/// Update C in the terminal encoding ca_low = 0x2f XOR C. The only persistent
/// state outside ca is `done`. The exact-trace proof establishes that a zero
/// logical C together with A=q=0 implies B=1 and the complete ca value p.
fn q949_affine_counter_update(
    c: &mut Circuit,
    aa: &[QReg],
    qq: &[QReg],
    ca: &[QReg],
    done: &QReg,
    candidates: &[&QReg],
    inverse: bool,
) {
    assert!(lowq_q949_affine_counter_enabled());
    let count: Vec<&QReg> = ca[..Q949_AFFINE_COUNTER_WIDTH].iter().collect();

    if inverse {
        q949_bracket_affine_count(c, ca);
        dirty_controlled_inc_suffix(c, &[done], &count, 0, true, candidates);
        q949_bracket_affine_count(c, ca);
    }

    let previous = c.push_section("p.q949.affine-boundary");
    q949_bracket_affine_count(c, ca);
    for lane in aa.iter().chain(qq).chain(ca[..Q949_AFFINE_COUNTER_WIDTH].iter()) {
        c.x(lane);
    }
    let controls: Vec<&QReg> = aa
        .iter()
        .chain(qq)
        .chain(ca[..Q949_AFFINE_COUNTER_WIDTH].iter())
        .collect();
    dirty_controlled_x(c, &controls, done, candidates, &[done]);
    for lane in aa
        .iter()
        .chain(qq)
        .chain(ca[..Q949_AFFINE_COUNTER_WIDTH].iter())
        .rev()
    {
        c.x(lane);
    }
    q949_bracket_affine_count(c, ca);
    c.pop_section(&previous);

    if !inverse {
        q949_bracket_affine_count(c, ca);
        dirty_controlled_inc_suffix(c, &[done], &count, 0, false, candidates);
        q949_bracket_affine_count(c, ca);
    }
}

fn q949_counter_export_core(
    c: &mut Circuit,
    ca: &[QReg],
    done: &QReg,
    saved: &[QReg],
    candidates: &[&QReg],
) {
    assert_eq!(saved.len(), Q949_AFFINE_COUNTER_WIDTH);
    q949_bracket_affine_count(c, ca);
    for i in 0..Q949_AFFINE_COUNTER_WIDTH {
        c.cx(&ca[i], &saved[i]);
        c.cx(&saved[i], &ca[i]);
    }
    q949_bracket_affine_count(c, ca);
    toggle_nonzero_dirty(c, saved, done, candidates, &[done]);
}

fn q949_counter_import_core(
    c: &mut Circuit,
    ca: &[QReg],
    done: &QReg,
    saved: &[QReg],
    candidates: &[&QReg],
) {
    assert_eq!(saved.len(), Q949_AFFINE_COUNTER_WIDTH);
    toggle_nonzero_dirty(c, saved, done, candidates, &[done]);
    q949_bracket_affine_count(c, ca);
    for i in 0..Q949_AFFINE_COUNTER_WIDTH {
        c.cx(&saved[i], &ca[i]);
        c.cx(&ca[i], &saved[i]);
    }
    q949_bracket_affine_count(c, ca);
}

/// Outside the EEA peak, export (E(C), done, S=0) to (p, 0, S=C).
fn q949_counter_export(c: &mut Circuit, ca: &[QReg], done: &QReg) -> Vec<QReg> {
    let saved = c.alloc_qreg_bits("q949.counter.saved", Q949_AFFINE_COUNTER_WIDTH);
    let candidates: Vec<&QReg> = ca.iter().chain(saved.iter()).chain(std::iter::once(done)).collect();
    q949_counter_export_core(c, ca, done, &saved, &candidates);
    saved
}

/// Before reverse EEA, import (p, 0, S=C) to (E(C), done, S=0).
fn q949_counter_import(c: &mut Circuit, ca: &[QReg], done: &QReg, saved: &mut Vec<QReg>) {
    assert_eq!(saved.len(), Q949_AFFINE_COUNTER_WIDTH);
    let candidates: Vec<&QReg> = ca.iter().chain(saved.iter()).chain(std::iter::once(done)).collect();
    q949_counter_import_core(c, ca, done, saved, &candidates);
    for lane in std::mem::take(saved) {
        c.zero_and_free(lane);
    }
}

/// Record a zero-operation liveness marker immediately before a row substep.
/// The marker is diagnostic metadata only: it neither changes the operation
/// stream nor assigns a Q-label to any measured peak.
fn hardened_peak_trace_marker(c: &mut Circuit, row: usize, inverse: bool, substep: &str) {
    if std::env::var("TRACE_LOWQ_LIVENESS").ok().as_deref() != Some("1") {
        return;
    }
    let direction = if inverse { "reverse" } else { "forward" };
    let passenger_enabled = passenger_top_lifetime_experiment_requested();
    let borrow_enabled = borrowed_transcript_experiment_requested();
    let [aa, bb, cca, ccb, qq, counter, s_rot] = c.lowq_trace_register_widths;
    c.b.record_lowq_liveness_marker(format!(
        concat!(
            "direction={};row={};substep={};",
            "passenger_enabled={};borrow_enabled={};",
            "passenger_releases={};lambda_releases={};",
            "aa={};bb={};cca={};ccb={};qq={};",
            "counter={};s_rot={};division_borrow={};",
            "multiply_borrow={};reverse_ca_enabled={};direct_hclz_guard={};",
            "off_counter_alias={};second_ownership_release={};local_hosts={}"
        ),
        direction,
        row,
        substep,
        passenger_enabled,
        borrow_enabled,
        c.lowq_passenger_top_releases,
        c.lowq_lambda_top_releases,
        aa,
        bb,
        cca,
        ccb,
        qq,
        counter,
        s_rot,
        c.lowq_trace_division_borrow,
        c.lowq_trace_multiply_borrow,
        reverse_ca255_relational_loan_requested(),
        c.lowq_q948_direct_hclz_peak_guard_active,
        lowq_q956_off_borrow_enabled(),
        q946_second_ownership_release_requested(),
        q945_local_hosts_requested(),
    ));
}

/// One forward (inverse=false) or backward (inverse=true) `shrunken_pz` step on the
/// dynamic-W registers at their current width. Resize is done by the caller.
#[allow(clippy::too_many_arguments)]
pub(crate) fn shrunken_pz_pass_step(
    c: &mut Circuit,
    aa: &[QReg],
    bb: &[QReg],
    cca: &[QReg],
    ccb: &[QReg],
    qq: &[QReg],
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    off: &QReg,
    i: usize,
    inverse: bool,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::shift_bounds;
    fn rb(b: usize) -> usize {
        if b == 0 {
            1
        } else {
            64 - (b as u64).leading_zeros() as usize
        }
    }
    let [lo_a, lo_b, ca_window, cb_window, _] = trailmix_register_los_step(i);
    let (sdb, s2b) = shift_bounds(i);
    let ctz_bits = q954_ctz_width(i);
    let q945_route = lowq_q945_local_hosts_enabled();
    let direct_hclz_binding = if q947_passenger_direct_hclz_requested() {
        let q946_second_release_binding = q946_second_ownership_release_requested()
            && Q946_SECOND_RELEASE_DIRECT_HCLZ_ROWS.contains(&i);
        let q945_local_binding = q945_route && Q945_HCLZ_ROWS.contains(&i);
        let q944_residual_binding = lowq_q944_residual_one_lane_cut_enabled()
            && Q944_RESIDUAL_HCLZ_ROWS.contains(&i);
        matches!(c.current_section.as_str(), "ec3.alt.cancel" | "ec3.inv_fwd")
            && (Q947_DIRECT_HCLZ_BINDING_ROWS.contains(&i)
                || q946_second_release_binding
                || q945_local_binding
                || q944_residual_binding)
    } else {
        inverse && Q948_DIRECT_HCLZ_BINDING_ROWS.contains(&i)
    };
    c.lowq_q948_direct_hclz_peak_guard_active = lowq_q948_direct_hclz_peak_guard_enabled()
        && direct_hclz_binding;
    if lowq_q954_srot_counter7_enabled() {
        assert_eq!(s_rot.len(), 4, "Q954 boundary must see four owned shift lanes");
        assert_eq!(counter.len(), 8, "Q954 boundary counter width");
        assert!(
            s_rot.iter().all(|lane| !std::ptr::eq(lane, &counter[7])),
            "Q954 boundary received the arithmetic-only counter[7] alias"
        );
        assert_eq!(
            ctz_bits,
            if i <= Q954_LAST_CTZ_BIT4_ROW { 5 } else { 4 },
            "Q954 CTZ bit4 cutoff drift"
        );
    }
    if lowq_q956_off_borrow_enabled() {
        assert_q956_off_alias(off, counter, s_rot);
        assert!(!std::ptr::eq(off, parity), "Q956 off aliases parity");
        assert!(
            aa.iter()
                .chain(bb.iter())
                .chain(cca.iter())
                .chain(ccb.iter())
                .chain(qq.iter())
                .all(|lane| !std::ptr::eq(off, lane)),
            "Q956 off alias overlaps a dynamic state register"
        );
    }
    // Swap, gated g_swap=(q==0 & A!=0 & active). HOLD the (q==0)/(A!=0) flags
    // across the cswaps so or_nonzero(A)/or_is_zero(q) run 2x not 4x per step
    // (the swap preserves both predicates: q untouched, A_new=B_old!=0).
    let swap = |c: &mut Circuit, active: &QReg| {
        let qz = c.alloc_qreg("sw.qz");
        let anz = c.alloc_qreg("sw.anz");
        or_is_zero(c, qq, &qz);
        or_nonzero(c, aa, &anz);
        let t = c.alloc_qreg("sw.t");
        let g = c.alloc_qreg("g_swap");
        c.ccx(&qz, &anz, &t); // t = (q==0 & A!=0)
        c.ccx(&t, active, &g); // g_swap = t AND active
        for j in 0..aa.len() {
            c.cswap(&g, &aa[j], &bb[j]);
        }
        for j in 0..cca.len() {
            c.cswap(&g, &cca[j], &ccb[j]);
        }
        c.cx(&g, parity);
        c.ccx(&t, active, &g); // uncompute g (t,active preserved)
        c.ccx(&qz, &anz, &t); // uncompute t (qz held; anz=A_old!=0)
        c.zero_and_free(g);
        c.zero_and_free(t);
        or_nonzero(c, aa, &anz); // post-swap A=B_old!=0 -> clears anz
        or_is_zero(c, qq, &qz);
        c.zero_and_free(anz);
        c.zero_and_free(qz);
    };

    let boundary_candidates: Vec<&QReg> = aa
        .iter()
        .chain(bb.iter())
        .chain(cca.iter())
        .chain(ccb.iter())
        .chain(qq.iter())
        .chain(counter.iter())
        .chain(s_rot.iter())
        .chain(std::iter::once(parity))
        .chain(std::iter::once(off))
        .collect();

    let update_terminal_counter = |c: &mut Circuit, inverse: bool| {
        if lowq_q949_affine_counter_enabled() {
            assert_eq!(counter.len(), 1, "Q949 owns one done lane");
            if i >= Q949_FIRST_TERMINAL_ROW {
                q949_affine_counter_update(
                    c,
                    aa,
                    qq,
                    cca,
                    &counter[0],
                    &boundary_candidates,
                    inverse,
                );
            }
        } else {
            done_counter_fn(
                c,
                aa,
                qq,
                counter,
                s_rot,
                off,
                &boundary_candidates,
                inverse,
            );
        }
    };
    let reverse_relational_division = inverse
        && i == BORROWED_ROW_380
        && lowq_reverse_ca255_relational_loan_enabled();
    let division_transcript_loans = q945_local_hclz_loans(
        i,
        inverse,
        BorrowedTranscriptSubstep::Division,
        aa,
        bb,
        cca,
        ccb,
        qq,
        counter,
        off,
    )
    .unwrap_or_else(|| {
        if reverse_relational_division {
            BorrowedTranscriptLoans::none()
        } else {
            BorrowedTranscriptLoans::shared(borrowed_transcript_loan(
                i,
                inverse,
                BorrowedTranscriptSubstep::Division,
                aa,
                cca,
                ccb,
                counter,
                None,
            ))
        }
    });
    let multiply_transcript_loans = q945_local_hclz_loans(
        i,
        inverse,
        BorrowedTranscriptSubstep::Multiply,
        aa,
        bb,
        cca,
        ccb,
        qq,
        counter,
        off,
    )
    .unwrap_or_else(|| {
        BorrowedTranscriptLoans::shared(borrowed_transcript_loan(
            i,
            inverse,
            BorrowedTranscriptSubstep::Multiply,
            aa,
            cca,
            ccb,
            counter,
            None,
        ))
    });
    let division_q945_carry = q945_narrow_carry(
        i,
        Q945Substep::Division,
        aa,
        bb,
        cca,
        ccb,
        qq,
        off,
        parity,
    );
    let multiply_q945_carry = q945_narrow_carry(
        i,
        Q945Substep::Multiply,
        aa,
        bb,
        cca,
        ccb,
        qq,
        off,
        parity,
    );
    c.lowq_trace_register_widths = [
        aa.len(),
        bb.len(),
        cca.len(),
        ccb.len(),
        qq.len(),
        counter.len(),
        s_rot.len(),
    ];
    c.lowq_trace_division_borrow = division_transcript_loans.update.is_some()
        || division_transcript_loans.parity.is_some()
        || reverse_relational_division;
    c.lowq_trace_multiply_borrow = multiply_transcript_loans.update.is_some()
        || multiply_transcript_loans.parity.is_some();

    if lowq_q959_selective_borrow_enabled() {
        if inverse {
            hardened_peak_trace_marker(c, i, true, "terminal");
            update_terminal_counter(c, true);
            hardened_peak_trace_marker(c, i, true, "swap");
            borrowed_swap_in_place(c, aa, bb, cca, ccb, qq, counter, parity, s_rot, off);

            hardened_peak_trace_marker(c, i, true, "division");
            let q944_full = lowq_q944_full_structural_enabled()
                && Q945_NON_HCLZ_ROWS.contains(&i);
            let division_mode = if q944_full
                && q944_full_gate_route(i, Q945Substep::Division)
                    == Q944FullGateRoute::QuotientWitness
            {
                Q944DivisionQuotientMode::QuotientWitness
            } else {
                Q944DivisionQuotientMode::Baseline
            };
            let division_body = |c: &mut Circuit, g: &QReg| {
                let relation_loan = reverse_relational_division
                    .then(|| {
                        borrowed_transcript_loan(
                            i,
                            true,
                            BorrowedTranscriptSubstep::Division,
                            aa,
                            cca,
                            ccb,
                            counter,
                            Some(g),
                        )
                    })
                    .flatten();
                let transcript_loans = relation_loan
                    .map(|loan| BorrowedTranscriptLoans::shared(Some(loan)))
                    .unwrap_or(division_transcript_loans);
                let lenders: Vec<&QReg> = cca.iter().chain(ccb.iter()).collect();
                with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                    division_substep_windowed_inv_mode(
                        c,
                        aa,
                        bb,
                        qq,
                        s_rot_arith,
                        off,
                        g,
                        &lenders,
                        lo_a,
                        lo_b,
                        rb(sdb),
                        ctz_bits,
                        transcript_loans,
                        division_q945_carry,
                        division_mode,
                    );
                });
            };
            if q944_full {
                q944_run_full_gate(
                    c,
                    i,
                    Q945Substep::Division,
                    true,
                    cca,
                    ccb,
                    aa,
                    bb,
                    cca,
                    ccb,
                    qq,
                    counter,
                    parity,
                    s_rot,
                    off,
                    &boundary_candidates,
                    division_body,
                );
            } else {
                let g_div = c.alloc_qreg("g_div");
                gate_hold_counter_zero(
                    c,
                    cca,
                    ccb,
                    counter,
                    parity,
                    s_rot,
                    &g_div,
                    &boundary_candidates,
                    division_body,
                );
                c.zero_and_free(g_div);
            }

            hardened_peak_trace_marker(c, i, true, "multiply");
            let multiply_body = |c: &mut Circuit, g: &QReg| {
                let lenders: Vec<&QReg> = aa.iter().chain(bb.iter()).collect();
                with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                    multiply_substep_windowed_inv(
                        c,
                        cca,
                        ccb,
                        qq,
                        s_rot_arith,
                        off,
                        g,
                        &lenders,
                        ca_window,
                        cb_window,
                        rb(s2b),
                        ctz_bits,
                        multiply_transcript_loans,
                        multiply_q945_carry,
                    );
                });
            };
            if q944_full {
                q944_run_full_gate(
                    c,
                    i,
                    Q945Substep::Multiply,
                    true,
                    aa,
                    bb,
                    aa,
                    bb,
                    cca,
                    ccb,
                    qq,
                    counter,
                    parity,
                    s_rot,
                    off,
                    &boundary_candidates,
                    multiply_body,
                );
            } else {
                let g_mul = c.alloc_qreg("g_mul");
                gate_hold_counter_zero(
                    c,
                    aa,
                    bb,
                    counter,
                    parity,
                    s_rot,
                    &g_mul,
                    &boundary_candidates,
                    multiply_body,
                );
                c.zero_and_free(g_mul);
            }
        } else {
            hardened_peak_trace_marker(c, i, false, "multiply");
            let q944_full = lowq_q944_full_structural_enabled()
                && Q945_NON_HCLZ_ROWS.contains(&i);
            let multiply_body = |c: &mut Circuit, g: &QReg| {
                let lenders: Vec<&QReg> = aa.iter().chain(bb.iter()).collect();
                with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                    multiply_substep_windowed(
                        c,
                        cca,
                        ccb,
                        qq,
                        s_rot_arith,
                        off,
                        g,
                        &lenders,
                        ca_window,
                        cb_window,
                        rb(s2b),
                        ctz_bits,
                        multiply_transcript_loans,
                        multiply_q945_carry,
                    );
                });
            };
            if q944_full {
                q944_run_full_gate(
                    c,
                    i,
                    Q945Substep::Multiply,
                    false,
                    aa,
                    bb,
                    aa,
                    bb,
                    cca,
                    ccb,
                    qq,
                    counter,
                    parity,
                    s_rot,
                    off,
                    &boundary_candidates,
                    multiply_body,
                );
            } else {
                let g_mul = c.alloc_qreg("g_mul");
                gate_hold_counter_zero(
                    c,
                    aa,
                    bb,
                    counter,
                    parity,
                    s_rot,
                    &g_mul,
                    &boundary_candidates,
                    multiply_body,
                );
                c.zero_and_free(g_mul);
            }

            hardened_peak_trace_marker(c, i, false, "division");
            let division_mode = if q944_full
                && q944_full_gate_route(i, Q945Substep::Division)
                    == Q944FullGateRoute::QuotientWitness
            {
                Q944DivisionQuotientMode::QuotientWitness
            } else {
                Q944DivisionQuotientMode::Baseline
            };
            let division_body = |c: &mut Circuit, g: &QReg| {
                let lenders: Vec<&QReg> = cca.iter().chain(ccb.iter()).collect();
                with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                    division_substep_windowed_mode(
                        c,
                        aa,
                        bb,
                        qq,
                        s_rot_arith,
                        off,
                        g,
                        &lenders,
                        lo_a,
                        lo_b,
                        rb(sdb),
                        ctz_bits,
                        division_transcript_loans,
                        division_q945_carry,
                        division_mode,
                    );
                });
            };
            if q944_full {
                q944_run_full_gate(
                    c,
                    i,
                    Q945Substep::Division,
                    false,
                    cca,
                    ccb,
                    aa,
                    bb,
                    cca,
                    ccb,
                    qq,
                    counter,
                    parity,
                    s_rot,
                    off,
                    &boundary_candidates,
                    division_body,
                );
            } else {
                let g_div = c.alloc_qreg("g_div");
                gate_hold_counter_zero(
                    c,
                    cca,
                    ccb,
                    counter,
                    parity,
                    s_rot,
                    &g_div,
                    &boundary_candidates,
                    division_body,
                );
                c.zero_and_free(g_div);
            }

            hardened_peak_trace_marker(c, i, false, "swap");
            borrowed_swap_in_place(c, aa, bb, cca, ccb, qq, counter, parity, s_rot, off);
            hardened_peak_trace_marker(c, i, false, "terminal");
            update_terminal_counter(c, false);
        }
        c.lowq_q948_direct_hclz_peak_guard_active = false;
        return;
    }

    if inverse {
        hardened_peak_trace_marker(c, i, true, "terminal");
        update_terminal_counter(c, true);
        let active = compute_active(c, counter, &boundary_candidates);
        hardened_peak_trace_marker(c, i, true, "swap");
        swap(c, &active); // self-inverse
        hardened_peak_trace_marker(c, i, true, "division");
        let g_div = c.alloc_qreg("g_div");
        gate_hold(
            c,
            cca,
            ccb,
            &active,
            &g_div,
            lowq_q959_selective_borrow_enabled().then_some(&s_rot[0]),
            |c, g| {
            let relation_loan = reverse_relational_division
                .then(|| {
                    borrowed_transcript_loan(
                        i,
                        true,
                        BorrowedTranscriptSubstep::Division,
                        aa,
                        cca,
                        ccb,
                        counter,
                        Some(g),
                    )
                })
                .flatten();
            let transcript_loans = relation_loan
                .map(|loan| BorrowedTranscriptLoans::shared(Some(loan)))
                .unwrap_or(division_transcript_loans);
            let lenders: Vec<&QReg> = cca.iter().chain(ccb.iter()).collect();
            with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                division_substep_windowed_inv(
                    c, aa, bb, qq, s_rot_arith, off, g, &lenders, lo_a, lo_b, rb(sdb),
                    ctz_bits, transcript_loans, division_q945_carry,
                );
            });
            },
        );
        c.zero_and_free(g_div);
        hardened_peak_trace_marker(c, i, true, "multiply");
        let g_mul = c.alloc_qreg("g_mul");
        gate_hold(
            c,
            aa,
            bb,
            &active,
            &g_mul,
            lowq_q959_selective_borrow_enabled().then_some(&s_rot[0]),
            |c, g| {
            let lenders: Vec<&QReg> = aa.iter().chain(bb.iter()).collect();
            with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                multiply_substep_windowed_inv(
                    c,
                    cca,
                    ccb,
                    qq,
                    s_rot_arith,
                    off,
                    g,
                    &lenders,
                    ca_window,
                    cb_window,
                    rb(s2b),
                    ctz_bits,
                    multiply_transcript_loans,
                    multiply_q945_carry,
                );
            });
            },
        );
        c.zero_and_free(g_mul);
        uncompute_active(c, counter, &active, &boundary_candidates);
        c.zero_and_free(active);
    } else {
        let active = compute_active(c, counter, &boundary_candidates);
        hardened_peak_trace_marker(c, i, false, "multiply");
        let g_mul = c.alloc_qreg("g_mul");
        gate_hold(
            c,
            aa,
            bb,
            &active,
            &g_mul,
            lowq_q959_selective_borrow_enabled().then_some(&s_rot[0]),
            |c, g| {
            let lenders: Vec<&QReg> = aa.iter().chain(bb.iter()).collect();
            with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                multiply_substep_windowed(
                    c,
                    cca,
                    ccb,
                    qq,
                    s_rot_arith,
                    off,
                    g,
                    &lenders,
                    ca_window,
                    cb_window,
                    rb(s2b),
                    ctz_bits,
                    multiply_transcript_loans,
                    multiply_q945_carry,
                );
            });
            },
        );
        c.zero_and_free(g_mul);
        hardened_peak_trace_marker(c, i, false, "division");
        let g_div = c.alloc_qreg("g_div");
        gate_hold(
            c,
            cca,
            ccb,
            &active,
            &g_div,
            lowq_q959_selective_borrow_enabled().then_some(&s_rot[0]),
            |c, g| {
            let lenders: Vec<&QReg> = cca.iter().chain(ccb.iter()).collect();
            with_arithmetic_srot_view(s_rot, counter, |s_rot_arith| {
                division_substep_windowed(
                    c, aa, bb, qq, s_rot_arith, off, g, &lenders, lo_a, lo_b, rb(sdb),
                    ctz_bits, division_transcript_loans, division_q945_carry,
                );
            });
            },
        );
        c.zero_and_free(g_div);
        hardened_peak_trace_marker(c, i, false, "swap");
        swap(c, &active);
        uncompute_active(c, counter, &active, &boundary_candidates);
        c.zero_and_free(active);
        hardened_peak_trace_marker(c, i, false, "terminal");
        update_terminal_counter(c, false);
    }
    c.lowq_q948_direct_hclz_peak_guard_active = false;
}

/// Resize a dynamic-W register to `target` bits: free high qubits (must be |0>)
/// or alloc fresh |0> ones, in place.
pub(crate) fn shrunken_pz_resize(c: &mut Circuit, reg: &mut Vec<QReg>, target: usize, name: &str) {
    while reg.len() > target {
        let q = reg.pop().unwrap();
        c.zero_and_free(q);
    }
    while reg.len() < target {
        let k = reg.len();
        reg.push(c.alloc_qreg(&format!("{name}[{k}]")));
    }
}

/// Drop the proven-clean top lane of the canonical persistent slope while the
/// backward EEA owns the peak. The canonical multiplier and field negation
/// guarantee the precondition `lambda[256] = |0>`.
pub(super) fn release_q955_canonical_lambda_top(c: &mut Circuit, lambda: &mut Vec<QReg>) {
    assert_eq!(
        lambda.len(),
        257,
        "Q955 canonical lambda must enter the reverse EEA with 257 lanes"
    );
    let active_before = c.b.active_qubits;
    let top = lambda.pop().expect("Q955 canonical lambda top lane");
    c.zero_and_free(top);
    assert_eq!(lambda.len(), 256, "Q955 reverse EEA keeps 256 lambda lanes");
    assert_eq!(
        c.b.active_qubits + 1,
        active_before,
        "Q955 canonical lambda release must save exactly one live qubit"
    );
    c.lowq_lambda_top_releases += 1;
}

/// Restore the public 257-bit slope shape with a newly allocated clean lane.
pub(super) fn restore_q955_canonical_lambda_top(c: &mut Circuit, lambda: &mut Vec<QReg>) {
    assert_eq!(
        lambda.len(),
        256,
        "Q955 canonical lambda must leave the reverse EEA with 256 lanes"
    );
    let active_before = c.b.active_qubits;
    lambda.push(c.alloc_qreg("shpzdiv.lambda[256].restored"));
    assert_eq!(lambda.len(), 257, "Q955 lambda API requires 257 lanes");
    assert_eq!(
        c.b.active_qubits,
        active_before + 1,
        "Q955 lambda top restoration must allocate exactly one clean qubit"
    );
    assert!(c.lowq_lambda_top_releases > 0, "lambda release state underflow");
    c.lowq_lambda_top_releases -= 1;
}

fn canonical_passenger_top_lifetime_enabled() -> bool {
    let q954 = lowq_q954_srot_counter7_enabled();
    let passenger_lifetime = lowq_passenger_top_lifetime_experiment_enabled();
    assert!(
        !(q954 && passenger_lifetime),
        "alternate srot and passenger-lifetime routes are exclusive"
    );
    q954 || passenger_lifetime || super::paper2607_eea::enabled()
}

/// Owns a canonical passenger lane while its physical qubit is inactive. The
/// lane ID is removed from the allocator free list, so no temporary can reuse it
/// before the matching restore explicitly reacquires that exact ID.
pub(super) struct ReleasedCanonicalPassengerTop {
    lane: Option<QReg>,
    physical_id: u32,
}

impl ReleasedCanonicalPassengerTop {
    fn physical_id(&self) -> u32 {
        self.physical_id
    }
}

impl Drop for ReleasedCanonicalPassengerTop {
    fn drop(&mut self) {
        assert!(
            self.lane.is_none() || std::thread::panicking(),
            "canonical passenger top dropped without symmetric restore"
        );
    }
}

/// Remove a canonical field passenger's proven-zero 257th lane while an EEA
/// traversal owns the peak. One reset records the clean release; the physical ID
/// remains reserved until the symmetric restore.
pub(super) fn release_canonical_passenger_top(
    c: &mut Circuit,
    passenger: &mut Vec<QReg>,
    context: &str,
) -> ReleasedCanonicalPassengerTop {
    use crate::circuit::{OperationType, QubitId};

    assert!(canonical_passenger_top_lifetime_enabled());
    assert_eq!(
        passenger.len(),
        257,
        "{context} canonical passenger must enter EEA with 257 lanes"
    );
    let live_before = c.b.active_qubits as usize;
    c.flush_pending_frees();
    let top = passenger.pop().expect("canonical passenger top lane");
    let physical_id = top.id();
    let resets_before = c.b.counted_kind_ops[OperationType::R as usize];
    c.b.free(QubitId(physical_id.into()));
    assert_eq!(
        c.b.counted_kind_ops[OperationType::R as usize],
        resets_before + 1,
        "{context} canonical passenger release must emit one reset"
    );
    let free_position = c
        .b
        .free_qubits
        .iter()
        .position(|&id| id == physical_id)
        .expect("released canonical passenger ID missing from free list");
    c.b.free_qubits.swap_remove(free_position);
    assert!(
        !c.b.free_qubits.contains(&physical_id),
        "{context} canonical passenger ID was not reserved"
    );
    assert_eq!(passenger.len(), 256, "{context} canonical passenger width");
    assert_eq!(
        c.b.active_qubits as usize + 1,
        live_before,
        "{context} canonical passenger release must save one live qubit"
    );
    c.lowq_passenger_top_releases += 1;
    ReleasedCanonicalPassengerTop {
        lane: Some(top),
        physical_id,
    }
}

pub(super) fn restore_canonical_passenger_top(
    c: &mut Circuit,
    passenger: &mut Vec<QReg>,
    mut released: ReleasedCanonicalPassengerTop,
    context: &str,
) {
    use crate::circuit::QubitId;

    assert!(canonical_passenger_top_lifetime_enabled());
    assert_eq!(
        passenger.len(),
        256,
        "{context} canonical passenger must leave EEA with 256 lanes"
    );
    let live_before = c.b.active_qubits as usize;
    let physical_id = released.physical_id;
    assert!(
        !c.b.free_qubits.contains(&physical_id),
        "{context} reserved passenger ID became allocator-visible"
    );
    c.b.free_qubits.push(physical_id);
    c.b.reacquire(QubitId(physical_id.into()));
    let lane = released
        .lane
        .take()
        .expect("canonical passenger top restored twice");
    assert_eq!(
        lane.id(),
        physical_id,
        "{context} restored a different physical passenger lane"
    );
    passenger.push(lane);
    assert_eq!(passenger.len(), 257, "canonical passenger API requires 257 lanes");
    assert_eq!(
        passenger[256].id(),
        physical_id,
        "{context} passenger top physical identity changed"
    );
    assert_eq!(
        c.b.active_qubits as usize,
        live_before + 1,
        "{context} passenger top restoration must reacquire one clean qubit"
    );
    assert!(
        c.lowq_passenger_top_releases > 0,
        "passenger release state underflow"
    );
    c.lowq_passenger_top_releases -= 1;
}

fn shrunken_pz_shrink(c: &mut Circuit, reg: &mut Vec<QReg>, target: usize) {
    while reg.len() > target {
        let q = reg.pop().unwrap();
        c.zero_and_free(q);
    }
}

#[allow(clippy::too_many_arguments)]
fn shrunken_pz_rebalance_pack(
    c: &mut Circuit,
    aa: &mut Vec<QReg>,
    bb: &mut Vec<QReg>,
    cca: &mut Vec<QReg>,
    ccb: &mut Vec<QReg>,
    qq: &mut Vec<QReg>,
    widths: [usize; 5],
    names: [&str; 5],
) {
    // Releasing every high lane first makes the transition peak equal to one
    // of its endpoint packs, never their component-wise union.
    let source_sum = aa.len() + bb.len() + cca.len() + ccb.len() + qq.len();
    let target_sum = widths.iter().sum::<usize>();
    let active_before = c.b.active_qubits as usize;
    assert!(active_before >= source_sum);
    let fixed_qubits = active_before - source_sum;
    let transition_peak_bound = fixed_qubits + source_sum.max(target_sum);
    shrunken_pz_shrink(c, aa, widths[0]);
    shrunken_pz_shrink(c, bb, widths[1]);
    shrunken_pz_shrink(c, cca, widths[2]);
    shrunken_pz_shrink(c, ccb, widths[3]);
    shrunken_pz_shrink(c, qq, widths[4]);
    assert!(c.b.active_qubits as usize <= transition_peak_bound);
    shrunken_pz_resize(c, aa, widths[0], names[0]);
    shrunken_pz_resize(c, bb, widths[1], names[1]);
    shrunken_pz_resize(c, cca, widths[2], names[2]);
    shrunken_pz_resize(c, ccb, widths[3], names[3]);
    shrunken_pz_resize(c, qq, widths[4], names[4]);
    assert!(c.b.active_qubits as usize <= transition_peak_bound);
    assert_eq!(
        [aa.len(), bb.len(), cca.len(), ccb.len(), qq.len()],
        widths
    );
    assert_eq!(c.b.active_qubits as usize, fixed_qubits + target_sum);
}

/// FORWARD `shrunken_pz` inversion driver. PRE: the registers hold the `S_0` state at width
/// `reg_widths(0)` -- A=p, B=|x| (sign-adjusted, < p/2), ca=0, cb=1, q=0,
/// counter=0, parity=1. Runs all `SHRUNKEN_PZ_NSTEPS` forward steps (resizing per step),
/// leaving the modular inverse of |x| in `ccb` (up to the `parity` bit: the true
/// value is `parity ? cb : p-cb`), with A=p, B=|x| at the EEA terminal. `s`,
/// `s_rot` (9 bits each), `off`, `parity`, `counter` (10 bits) are fixed-width.
#[allow(clippy::too_many_arguments)]
pub(crate) fn shrunken_pz_invert_forward(
    c: &mut Circuit,
    aa: &mut Vec<QReg>,
    bb: &mut Vec<QReg>,
    cca: &mut Vec<QReg>,
    ccb: &mut Vec<QReg>,
    qq: &mut Vec<QReg>,
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    off: &QReg,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::SHRUNKEN_PZ_NSTEPS;
    for i in 0..SHRUNKEN_PZ_NSTEPS {
        hardened_peak_trace_marker(c, i, false, "resize");
        let widths = trailmix_register_widths_step(i);
        shrunken_pz_rebalance_pack(
            c,
            aa,
            bb,
            cca,
            ccb,
            qq,
            widths,
            ["A", "B", "ca", "cb", "q"],
        );
        shrunken_pz_pass_step(
            c, aa, bb, cca, ccb, qq, counter, parity, s_rot, off, i, false,
        );
    }
}

/// BACKWARD `shrunken_pz` inversion driver (gate-for-gate inverse of `shrunken_pz_invert_forward`).
/// Restores the `S_0` state (A=p, B=|x|, ca=0, cb=1, q=0, counter=0, parity=1) and
/// uncomputes the inverse from `ccb`. Resizes back down per step.
#[allow(clippy::too_many_arguments)]
pub(crate) fn shrunken_pz_invert_backward(
    c: &mut Circuit,
    aa: &mut Vec<QReg>,
    bb: &mut Vec<QReg>,
    cca: &mut Vec<QReg>,
    ccb: &mut Vec<QReg>,
    qq: &mut Vec<QReg>,
    counter: &[QReg],
    parity: &QReg,
    s_rot: &[QReg],
    off: &QReg,
) {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::SHRUNKEN_PZ_NSTEPS;
    for i in (0..SHRUNKEN_PZ_NSTEPS).rev() {
        shrunken_pz_pass_step(
            c, aa, bb, cca, ccb, qq, counter, parity, s_rot, off, i, true,
        );
        if i > 0 {
            hardened_peak_trace_marker(c, i - 1, true, "resize");
            let widths = trailmix_register_widths_step(i - 1);
            shrunken_pz_rebalance_pack(
                c,
                aa,
                bb,
                cca,
                ccb,
                qq,
                widths,
                ["A", "B", "ca", "cb", "q"],
            );
        }
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q949Row370CleanupReport {
    pub first_row: usize,
    pub last_row: usize,
    pub forward_rows_checked: usize,
    pub reverse_rows_checked: usize,
    pub resize_boundaries_checked: usize,
    pub gate_allocation_cleanup_checks: usize,
    pub row_370_pack: [usize; 5],
    pub initial_active_qubits: usize,
    pub final_active_qubits: usize,
    pub peak_active_qubits: usize,
    pub emitted_ops: usize,
}

/// Build the exact production gates around the repaired row and its adjacent
/// resize boundaries. This is a structural cleanup check: every forward and
/// reverse step must return its temporary allocations, and the reverse resize
/// sequence must restore the row-369 interface width exactly.
#[doc(hidden)]
pub fn q949_row_369_371_resize_gate_cleanup_check() -> Q949Row370CleanupReport {
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::{
        Q949_REPAIRED_ROW, Q949_ROW_370_EFFECTIVE_PACK,
    };

    const FIRST_ROW: usize = Q949_REPAIRED_ROW - 1;
    const LAST_ROW: usize = Q949_REPAIRED_ROW + 1;

    fn resize_registers(
        c: &mut Circuit,
        aa: &mut Vec<QReg>,
        bb: &mut Vec<QReg>,
        cca: &mut Vec<QReg>,
        ccb: &mut Vec<QReg>,
        qq: &mut Vec<QReg>,
        widths: [usize; 5],
    ) {
        shrunken_pz_shrink(c, aa, widths[0]);
        shrunken_pz_shrink(c, bb, widths[1]);
        shrunken_pz_shrink(c, cca, widths[2]);
        shrunken_pz_shrink(c, ccb, widths[3]);
        shrunken_pz_shrink(c, qq, widths[4]);
        shrunken_pz_resize(c, aa, widths[0], "q949-row-check.A");
        shrunken_pz_resize(c, bb, widths[1], "q949-row-check.B");
        shrunken_pz_resize(c, cca, widths[2], "q949-row-check.ca");
        shrunken_pz_resize(c, ccb, widths[3], "q949-row-check.cb");
        shrunken_pz_resize(c, qq, widths[4], "q949-row-check.q");
        assert_eq!(
            [aa.len(), bb.len(), cca.len(), ccb.len(), qq.len()],
            widths
        );
    }

    assert!(lowq_q949_affine_counter_enabled());
    let initial_pack = trailmix_register_widths_step(FIRST_ROW);
    assert_eq!(
        trailmix_register_widths_step(Q949_REPAIRED_ROW),
        Q949_ROW_370_EFFECTIVE_PACK
    );

    let mut c = Circuit::new();
    let mut aa = c.alloc_qreg_bits("q949-row-check.A", initial_pack[0]);
    let mut bb = c.alloc_qreg_bits("q949-row-check.B", initial_pack[1]);
    let mut cca = c.alloc_qreg_bits("q949-row-check.ca", initial_pack[2]);
    let mut ccb = c.alloc_qreg_bits("q949-row-check.cb", initial_pack[3]);
    let mut qq = c.alloc_qreg_bits("q949-row-check.q", initial_pack[4]);
    let counter = c.alloc_qreg_bits("q949-row-check.done", 1);
    let parity = c.alloc_qreg("q949-row-check.parity");
    let s_rot = c.alloc_qreg_bits("q949-row-check.s-rot", 5);
    let off = c.alloc_qreg("q949-row-check.off");
    let initial_active_qubits = c.b.active_qubits as usize;
    assert_eq!(
        initial_active_qubits,
        initial_pack.iter().sum::<usize>() + counter.len() + s_rot.len() + 2
    );

    let mut resize_boundaries_checked = 0usize;
    let mut gate_allocation_cleanup_checks = 0usize;
    for row in FIRST_ROW..=LAST_ROW {
        let widths = trailmix_register_widths_step(row);
        resize_registers(
            &mut c, &mut aa, &mut bb, &mut cca, &mut ccb, &mut qq, widths,
        );
        c.flush_pending_frees();
        assert_eq!(
            c.b.active_qubits as usize,
            widths.iter().sum::<usize>() + counter.len() + s_rot.len() + 2
        );
        resize_boundaries_checked += 1;

        let active_before = c.b.active_qubits;
        shrunken_pz_pass_step(
            &mut c, &aa, &bb, &cca, &ccb, &qq, &counter, &parity, &s_rot, &off,
            row, false,
        );
        c.flush_pending_frees();
        assert_eq!(
            c.b.active_qubits, active_before,
            "Q949 forward row {row} leaked a gate allocation"
        );
        gate_allocation_cleanup_checks += 1;
    }

    for row in (FIRST_ROW..=LAST_ROW).rev() {
        let active_before = c.b.active_qubits;
        shrunken_pz_pass_step(
            &mut c, &aa, &bb, &cca, &ccb, &qq, &counter, &parity, &s_rot, &off,
            row, true,
        );
        c.flush_pending_frees();
        assert_eq!(
            c.b.active_qubits, active_before,
            "Q949 reverse row {row} leaked a gate allocation"
        );
        gate_allocation_cleanup_checks += 1;

        if row > FIRST_ROW {
            let widths = trailmix_register_widths_step(row - 1);
            resize_registers(
                &mut c, &mut aa, &mut bb, &mut cca, &mut ccb, &mut qq, widths,
            );
            c.flush_pending_frees();
            assert_eq!(
                c.b.active_qubits as usize,
                widths.iter().sum::<usize>() + counter.len() + s_rot.len() + 2
            );
            resize_boundaries_checked += 1;
        }
    }

    assert_eq!(
        [aa.len(), bb.len(), cca.len(), ccb.len(), qq.len()],
        initial_pack
    );
    let final_active_qubits = c.b.active_qubits as usize;
    assert_eq!(final_active_qubits, initial_active_qubits);
    let builder = c.into_builder();

    Q949Row370CleanupReport {
        first_row: FIRST_ROW,
        last_row: LAST_ROW,
        forward_rows_checked: LAST_ROW - FIRST_ROW + 1,
        reverse_rows_checked: LAST_ROW - FIRST_ROW + 1,
        resize_boundaries_checked,
        gate_allocation_cleanup_checks,
        row_370_pack: Q949_ROW_370_EFFECTIVE_PACK,
        initial_active_qubits,
        final_active_qubits,
        peak_active_qubits: builder.peak_qubits as usize,
        emitted_ops: builder.ops.len(),
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q949RobustResizeOrderingReport {
    pub rows_checked: usize,
    pub forward_transitions_checked: usize,
    pub reverse_transitions_checked: usize,
    pub peak_neutral_transitions_checked: usize,
    pub maximum_row_sum: usize,
    pub observed_peak_qubits: usize,
    pub final_active_qubits: usize,
}

/// Replay every adjacent schedule transition through the same shrink-before-grow
/// helper used by the production forward and reverse drivers. Registers remain
/// clean throughout this resize-only proof, so the observed allocator peak binds
/// the transition ordering without constructing the full arithmetic circuit.
#[doc(hidden)]
pub fn q949_robust_resize_ordering_check() -> Q949RobustResizeOrderingReport {
    use super::q949_robust_envelope::{Q949_ROBUST_ROWS, Q949_ROBUST_TARGET_SUM};

    assert!(lowq_q949_affine_counter_enabled());
    assert!(q949_robust_symmetric_schedule_requested());
    assert_eq!(
        Q949_ROBUST_ROWS,
        crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::SHRUNKEN_PZ_NSTEPS
    );

    let initial = trailmix_register_widths_step(0);
    let mut c = Circuit::new();
    let mut aa = c.alloc_qreg_bits("q949-robust-resize.A", initial[0]);
    let mut bb = c.alloc_qreg_bits("q949-robust-resize.B", initial[1]);
    let mut cca = c.alloc_qreg_bits("q949-robust-resize.ca", initial[2]);
    let mut ccb = c.alloc_qreg_bits("q949-robust-resize.cb", initial[3]);
    let mut qq = c.alloc_qreg_bits("q949-robust-resize.q", initial[4]);
    assert_eq!(c.b.active_qubits as usize, initial.iter().sum::<usize>());

    let mut maximum_row_sum = initial.iter().sum::<usize>();
    let mut forward_transitions_checked = 0usize;
    for row in 1..Q949_ROBUST_ROWS {
        let widths = trailmix_register_widths_step(row);
        maximum_row_sum = maximum_row_sum.max(widths.iter().sum::<usize>());
        shrunken_pz_rebalance_pack(
            &mut c,
            &mut aa,
            &mut bb,
            &mut cca,
            &mut ccb,
            &mut qq,
            widths,
            [
                "q949-robust-resize.A",
                "q949-robust-resize.B",
                "q949-robust-resize.ca",
                "q949-robust-resize.cb",
                "q949-robust-resize.q",
            ],
        );
        assert_eq!(c.b.active_qubits as usize, widths.iter().sum::<usize>());
        forward_transitions_checked += 1;
    }

    let mut reverse_transitions_checked = 0usize;
    for row in (0..Q949_ROBUST_ROWS - 1).rev() {
        let widths = trailmix_register_widths_step(row);
        shrunken_pz_rebalance_pack(
            &mut c,
            &mut aa,
            &mut bb,
            &mut cca,
            &mut ccb,
            &mut qq,
            widths,
            [
                "q949-robust-resize.A",
                "q949-robust-resize.B",
                "q949-robust-resize.ca",
                "q949-robust-resize.cb",
                "q949-robust-resize.q",
            ],
        );
        assert_eq!(c.b.active_qubits as usize, widths.iter().sum::<usize>());
        reverse_transitions_checked += 1;
    }
    assert_eq!([aa.len(), bb.len(), cca.len(), ccb.len(), qq.len()], initial);
    assert!(maximum_row_sum <= Q949_ROBUST_TARGET_SUM);
    assert_eq!(forward_transitions_checked, Q949_ROBUST_ROWS - 1);
    assert_eq!(reverse_transitions_checked, Q949_ROBUST_ROWS - 1);

    for lane in aa.into_iter().chain(bb).chain(cca).chain(ccb).chain(qq) {
        c.zero_and_free(lane);
    }
    c.flush_pending_frees();
    let final_active_qubits = c.b.active_qubits as usize;
    assert_eq!(final_active_qubits, 0, "Q949 robust resize proof leaked ancillae");
    let builder = c.into_builder();
    let observed_peak_qubits = builder.peak_qubits as usize;
    assert_eq!(
        observed_peak_qubits, maximum_row_sum,
        "Q949 robust transition exceeded an endpoint pack"
    );

    Q949RobustResizeOrderingReport {
        rows_checked: Q949_ROBUST_ROWS,
        forward_transitions_checked,
        reverse_transitions_checked,
        peak_neutral_transitions_checked: forward_transitions_checked
            + reverse_transitions_checked,
        maximum_row_sum,
        observed_peak_qubits,
        final_active_qubits,
    }
}

/// `lambda = dy / dx mod p`, with `dx` and `dy` PRESERVED. `dx`, `dy` are 257-bit
/// registers holding field elements in [0, p). Returns `(dx, dy, lambda)` -- dx
/// and dy unchanged (dy reconstructed via the HMR-ghost trick), lambda = dy·dx^-1.
/// With `LOWQ_Q955_OFF_CANONICAL=1`, lambda is produced by the exact canonical
/// multiplier and its clean top lane is absent during reverse EEA. The API still
/// returns 257 lanes by appending a new clean top lane afterward.
/// With Q954 or the structural-only `LOWQ_PASSENGER_TOP_LIFETIME_EXPERIMENT=1`,
/// canonical dy[256] is likewise absent during the initial forward EEA and is
/// restored with the same physical ID after the constant pack is removed.
pub fn shrunken_pz_divide_forward(
    c: &mut Circuit,
    mut dx: Vec<QReg>,
    mut dy: Vec<QReg>,
) -> (Vec<QReg>, Vec<QReg>, Vec<QReg>) {
    use crate::point_add::trailmix_port::arith::compare::compare_geq_const;
    use crate::point_add::trailmix_port::arith::rfold_mbu::{
        mod_mul_canonical_mbu, mod_mul_rfold_mbu,
    };
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::reg_widths;
    use crate::point_add::trailmix_port::num_bigint::BigUint;
    assert_eq!(dx.len(), 257);
    assert_eq!(dy.len(), 257);
    let canonical_lambda_top_off = lowq_q955_off_canonical_enabled();
    let released_dy_top = canonical_passenger_top_lifetime_enabled()
        .then(|| release_canonical_passenger_top(c, &mut dy, "divide-forward dy"));
    // sgn = dx > p/2  <=>  dx >= (p+1)/2.
    let half_bytes = vec![
        0x18, 0xfe, 0xff, 0x7f, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0x7f, 0x00,
    ];
    let p_bytes = crate::point_add::trailmix_port::mod_arith::SECP256K1_P_LE;

    // --- sign-adjust dx -> |dx| < p/2 (the schedule assumes |x| < p/2) ---
    let reuse_sign_wire = sign_parity_q_reuse_enabled();
    let mut fused_parity = reuse_sign_wire.then(|| c.alloc_qreg("shpzdiv.par_sgn"));
    let sgn = (!reuse_sign_wire).then(|| c.alloc_qreg("shpzdiv.sgn"));
    let sign_control = fused_parity.as_ref().or(sgn.as_ref()).unwrap();
    compare_geq_const(c, &dx, &half_bytes, sign_control);
    controlled_field_neg(c, sign_control, &dx); // dx := (sgn ? p-dx : dx) = |dx|

    // --- set up the inversion S_0 state (B = |dx|, A = p, cb = 1, parity = 1) ---
    let (a0, b0, ca0, cb0, q0) = reg_widths(0);
    let initial_pack = if q949_robust_symmetric_schedule_requested() {
        trailmix_register_widths_step(0)
    } else {
        [
            a0.max(b0),
            a0.max(b0),
            ca0.max(cb0),
            ca0.max(cb0),
            q0.max(1),
        ]
    };
    shrunken_pz_resize(c, &mut dx, initial_pack[1], "B"); // |dx| becomes the EEA B register
    let mut aa = c.alloc_qreg_bits("shpzdiv.A", initial_pack[0]);
    let mut cca = c.alloc_qreg_bits("shpzdiv.ca", initial_pack[2]);
    let mut ccb = c.alloc_qreg_bits("shpzdiv.cb", initial_pack[3]);
    let mut qq = c.alloc_qreg_bits("shpzdiv.q", initial_pack[4]);
    let s_rot = c.alloc_qreg_bits("shpzdiv.srot", trailmix_srot_width());
    let parity = fused_parity
        .take()
        .unwrap_or_else(|| c.alloc_qreg("shpzdiv.par"));
    let counter = c.alloc_qreg_bits("shpzdiv.ctr", trailmix_counter_width());
    let off_owned = (!lowq_q956_off_borrow_enabled()).then(|| c.alloc_qreg("shpzdiv.off"));
    let off = off_owned.as_ref().unwrap_or_else(|| {
        assert_q956_off_alias(&counter[0], &counter, &s_rot);
        &counter[0]
    });
    let load_p = |c: &mut Circuit, reg: &[QReg]| {
        for (j, q) in reg.iter().enumerate() {
            if j < 256 && (p_bytes[j / 8] >> (j % 8)) & 1 == 1 {
                c.x(q);
            }
        }
    };
    load_p(c, &aa); // A = p
    c.x(&ccb[0]); // cb = 1
    c.x(&parity); // parity = 1, or fused parity = 1 XOR sign

    // --- forward inversion: 1/|dx| in cb (up to the parity bit) ---
    shrunken_pz_invert_forward(
        c, &mut aa, &mut dx, &mut cca, &mut ccb, &mut qq, &counter, &parity, &s_rot, off,
    );

    let mut saved_affine_counter = if lowq_q949_affine_counter_enabled() {
        assert_eq!(counter.len(), 1, "Q949 forward mode width");
        Some(q949_counter_export(c, &cca, &counter[0]))
    } else {
        None
    };

    // --- TEAR DOWN the EEA pack before creating lambda. At convergence the PZ
    // state is A=0, B=1, ca=p, q=0 (all CONSTANTS) and cb=1/|dx| (the only data).
    // Free the constant registers (0-Toffoli uncompute) so only cb is live during
    // the multiply -- saves ~ca(258) qubits at the peak. Re-create them (cheap)
    // before the backward. ---
    let (ta, tb, tca, tq) = (aa.len(), dx.len(), cca.len(), qq.len());
    load_p(c, &cca); // ca: p -> 0
    c.x(&dx[0]); // B: 1 -> 0
    for q in std::mem::take(&mut aa) {
        c.zero_and_free(q); // A = 0
    }
    for q in std::mem::take(&mut dx) {
        c.zero_and_free(q); // B = 0
    }
    for q in std::mem::take(&mut cca) {
        c.zero_and_free(q); // ca = 0
    }
    for q in std::mem::take(&mut qq) {
        c.zero_and_free(q); // q = 0
    }
    if let Some(released) = released_dy_top {
        restore_canonical_passenger_top(c, &mut dy, released, "divide-forward dy");
    }
    // --- lambda = dy * (1/|dx|), parity/sign corrected (only cb live in the pack) ---
    let cb_w = ccb.len();
    shrunken_pz_resize(c, &mut ccb, 257, "cb"); // pad the inverse to 257 for mod_mul
    let mut lambda = c.alloc_qreg_bits("shpzdiv.lambda", 257);
    if canonical_lambda_top_off {
        mod_mul_canonical_mbu(c, &lambda, &ccb[..257], &dy);
    } else {
        mod_mul_rfold_mbu(c, &lambda, &ccb[..257], &dy); // lambda_raw = dy * cb
    }
    shrunken_pz_resize(c, &mut ccb, cb_w, "cb"); // restore width for the backward
    // 1/dx = (-1)^{sgn + (1-parity)} * cb. With fusion, the live parity
    // lane already equals sgn XOR parity, so its X-bracket is exactly f.
    if reuse_sign_wire {
        c.x(&parity);
        if canonical_lambda_top_off {
            controlled_field_neg_canonical(c, &parity, &lambda);
        } else {
            controlled_field_neg(c, &parity, &lambda);
        }
        c.x(&parity);
    } else {
        let sgn = sgn.as_ref().unwrap();
        let f = c.alloc_qreg("shpzdiv.negf");
        c.cx(sgn, &f);
        c.cx(&parity, &f);
        c.x(&f); // f = NOT(sgn XOR parity)
        if canonical_lambda_top_off {
            controlled_field_neg_canonical(c, &f, &lambda);
        } else {
            controlled_field_neg(c, &f, &lambda);
        }
        c.x(&f);
        c.cx(&parity, &f);
        c.cx(sgn, &f); // uncompute f
        c.zero_and_free(f);
    }

    if canonical_lambda_top_off {
        release_q955_canonical_lambda_top(c, &mut lambda);
    }

    // --- GHOST dy (HMR each bit) so the reverse runs dy-free ---
    let mut ghosts = Vec::with_capacity(dy.len());
    for q in &dy {
        ghosts.push(c.hmr_ghost(q));
    }
    for q in dy {
        c.zero_and_free(q);
    }
    // --- RE-CREATE the constant pack (A=0, B=1, ca=p, q=0) for the backward ---
    aa = c.alloc_qreg_bits("shpzdiv.A", ta); // A = 0
    dx = c.alloc_qreg_bits("shpzdiv.B", tb);
    c.x(&dx[0]); // B = 1
    cca = c.alloc_qreg_bits("shpzdiv.ca", tca);
    load_p(c, &cca); // ca = p
    qq = c.alloc_qreg_bits("shpzdiv.q", tq); // q = 0
    if let Some(saved) = saved_affine_counter.as_mut() {
        q949_counter_import(c, &cca, &counter[0], saved);
    }

    // --- backward inversion: restore B = |dx|, uncompute cb/parity ---
    shrunken_pz_invert_backward(
        c, &mut aa, &mut dx, &mut cca, &mut ccb, &mut qq, &counter, &parity, &s_rot, off,
    );

    // --- free the clean inversion ancillas (S_0: A=p, ca=0, cb=1, q=0) ---
    if !reuse_sign_wire {
        c.x(&parity);
    }
    c.x(&ccb[0]); // cb: 1 -> 0
    load_p(c, &aa); // A: p -> 0
    for q in aa.into_iter().chain(cca).chain(ccb).chain(qq) {
        c.zero_and_free(q);
    }
    if let Some(off) = off_owned {
        c.zero_and_free(off);
    }
    for q in s_rot.into_iter().chain(counter) {
        c.zero_and_free(q);
    }

    // --- un-sign-adjust: |dx| -> dx, uncompute sign state ---
    shrunken_pz_resize(c, &mut dx, 257, "dx");
    if reuse_sign_wire {
        // Reverse EEA restored fused parity = 1 XOR sign.
        c.x(&parity);
        controlled_field_neg(c, &parity, &dx);
        compare_geq_const(c, &dx, &half_bytes, &parity);
        c.zero_and_free(parity);
    } else {
        let sgn = sgn.unwrap();
        controlled_field_neg(c, &sgn, &dx);
        compare_geq_const(c, &dx, &half_bytes, &sgn);
        c.zero_and_free(sgn);
        c.zero_and_free(parity);
    }

    // --- reconstruct dy = lambda * dx and EXORCIZE the ghosts ---
    if canonical_lambda_top_off {
        restore_q955_canonical_lambda_top(c, &mut lambda);
    }
    assert_eq!(lambda.len(), 257, "slope API and raw dy roundtrip require 257 lanes");
    let dy_new = c.alloc_qreg_bits("shpzdiv.dy", 257);
    if canonical_lambda_top_off {
        mod_mul_canonical_mbu(c, &dy_new, &lambda[..257], &dx);
    } else {
        mod_mul_rfold_mbu(c, &dy_new, &lambda[..257], &dx);
    }
    for (g, q) in ghosts.into_iter().zip(dy_new.iter()) {
        c.resolve_ghost(g, q);
    }

    (dx, dy_new, lambda)
}

/// CANCEL the `shrunken_pz` slope: given `lambda` = `new_dy` / `new_dx` (live, 257), drive it to
/// |0> and FREE it, with `new_dx` (dx) and `new_dy` (dy) PRESERVED. Returns
/// (`new_dx`, `new_dy`). By EC linearity `new_dy/new_dx` == lambda, so this is the
/// alt-witness cleanup that removes the slope ancilla after the point coordinates
/// are computed.
///
/// Mirror of `shrunken_pz_divide_forward`, but it GHOSTS lambda (not dy) up front so only
/// `new_dy` rides through the inversion as the passenger (peak = EEA-peak + 256, same
/// as forward). After inverting `new_dx` -> cb = `1/|new_dx`|, it recomputes
/// temp = `new_dy` * cb (parity/sign corrected) = `new_dy/new_dx` == lambda's original
/// value, resolves the lambda-ghost against temp (exorcizing it), uncomputes temp
/// through the matching route-specific multiplier inverse, then reverse-inverts
/// to restore `new_dx`. On Q954 and structural-only passenger lifetime, canonical new_dy[256]
/// is released independently around both EEA traversals and restored with the
/// same physical ID for the intervening multiply and final API result.
pub fn shrunken_pz_divide_cancel(
    c: &mut Circuit,
    mut dx: Vec<QReg>,
    mut dy: Vec<QReg>,
    lambda: Vec<QReg>,
) -> (Vec<QReg>, Vec<QReg>) {
    use crate::point_add::trailmix_port::arith::compare::compare_geq_const;
    use crate::point_add::trailmix_port::arith::rfold_mbu::{
        mod_mul_canonical_mbu, mod_mul_canonical_mbu_undo, mod_mul_rfold_mbu,
        mod_mul_rfold_mbu_undo,
    };
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::reg_widths;
    use crate::point_add::trailmix_port::num_bigint::BigUint;
    assert_eq!(dx.len(), 257);
    assert_eq!(dy.len(), 257);
    assert_eq!(lambda.len(), 257);
    let canonical_lambda = lowq_q955_off_canonical_enabled();
    let released_forward_dy_top = canonical_passenger_top_lifetime_enabled()
        .then(|| release_canonical_passenger_top(c, &mut dy, "cancel-forward new_dy"));
    let half_bytes = vec![
        0x18, 0xfe, 0xff, 0x7f, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff,
        0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0xff, 0x7f, 0x00,
    ];
    let p_bytes = crate::point_add::trailmix_port::mod_arith::SECP256K1_P_LE;

    // --- sign-adjust new_dx -> |new_dx| < p/2 ---
    let reuse_sign_wire = sign_parity_q_reuse_enabled();
    let mut fused_parity = reuse_sign_wire.then(|| c.alloc_qreg("shpzcan.par_sgn"));
    let sgn = (!reuse_sign_wire).then(|| c.alloc_qreg("shpzcan.sgn"));
    let sign_control = fused_parity.as_ref().or(sgn.as_ref()).unwrap();
    compare_geq_const(c, &dx, &half_bytes, sign_control);
    controlled_field_neg(c, sign_control, &dx);

    // --- GHOST lambda (HMR each bit, free 257q) so the inversion runs lambda-free;
    // new_dy is the sole 256-bit passenger (peak = EEA-peak + 256). ---
    let mut lam_ghosts = Vec::with_capacity(lambda.len());
    for q in &lambda {
        lam_ghosts.push(c.hmr_ghost(q));
    }
    for q in lambda {
        c.zero_and_free(q);
    }

    // --- set up the inversion S_0 (B = |new_dx|, A = p, cb = 1, parity = 1) ---
    let (a0, b0, ca0, cb0, q0) = reg_widths(0);
    let initial_pack = if q949_robust_symmetric_schedule_requested() {
        trailmix_register_widths_step(0)
    } else {
        [
            a0.max(b0),
            a0.max(b0),
            ca0.max(cb0),
            ca0.max(cb0),
            q0.max(1),
        ]
    };
    shrunken_pz_resize(c, &mut dx, initial_pack[1], "B");
    let mut aa = c.alloc_qreg_bits("shpzcan.A", initial_pack[0]);
    let mut cca = c.alloc_qreg_bits("shpzcan.ca", initial_pack[2]);
    let mut ccb = c.alloc_qreg_bits("shpzcan.cb", initial_pack[3]);
    let mut qq = c.alloc_qreg_bits("shpzcan.q", initial_pack[4]);
    let s_rot = c.alloc_qreg_bits("shpzcan.srot", trailmix_srot_width());
    let parity = fused_parity
        .take()
        .unwrap_or_else(|| c.alloc_qreg("shpzcan.par"));
    let counter = c.alloc_qreg_bits("shpzcan.ctr", trailmix_counter_width());
    let off_owned = (!lowq_q956_off_borrow_enabled()).then(|| c.alloc_qreg("shpzcan.off"));
    let off = off_owned.as_ref().unwrap_or_else(|| {
        assert_q956_off_alias(&counter[0], &counter, &s_rot);
        &counter[0]
    });
    let load_p = |c: &mut Circuit, reg: &[QReg]| {
        for (j, q) in reg.iter().enumerate() {
            if j < 256 && (p_bytes[j / 8] >> (j % 8)) & 1 == 1 {
                c.x(q);
            }
        }
    };
    load_p(c, &aa);
    c.x(&ccb[0]);
    c.x(&parity); // parity = 1, or fused parity = 1 XOR sign

    // --- forward inversion: 1/|new_dx| in cb (passenger: new_dy) ---
    shrunken_pz_invert_forward(
        c, &mut aa, &mut dx, &mut cca, &mut ccb, &mut qq, &counter, &parity, &s_rot, off,
    );

    let mut saved_affine_counter = if lowq_q949_affine_counter_enabled() {
        assert_eq!(counter.len(), 1, "Q949 cancel-forward mode width");
        Some(q949_counter_export(c, &cca, &counter[0]))
    } else {
        None
    };

    // --- tear down the constant pack (A=0,B=1,ca=p,q=0); keep cb=1/|new_dx| ---
    let (ta, tb, tca, tq) = (aa.len(), dx.len(), cca.len(), qq.len());
    load_p(c, &cca);
    c.x(&dx[0]);
    for q in std::mem::take(&mut aa) {
        c.zero_and_free(q);
    }
    for q in std::mem::take(&mut dx) {
        c.zero_and_free(q);
    }
    for q in std::mem::take(&mut cca) {
        c.zero_and_free(q);
    }
    for q in std::mem::take(&mut qq) {
        c.zero_and_free(q);
    }
    if let Some(released) = released_forward_dy_top {
        restore_canonical_passenger_top(c, &mut dy, released, "cancel-forward new_dy");
    }
    // --- temp = new_dy * (1/|new_dx|), parity/sign corrected = new_dy/new_dx, the
    // original value of lambda. Resolve the lambda-ghost against it, then uncompute
    // temp. ---
    let cb_w = ccb.len();
    shrunken_pz_resize(c, &mut ccb, 257, "cb");
    let temp = c.alloc_qreg_bits("shpzcan.temp", 257);
    if canonical_lambda {
        mod_mul_canonical_mbu(c, &temp, &ccb[..257], &dy);
    } else {
        mod_mul_rfold_mbu(c, &temp, &ccb[..257], &dy);
    }
    if reuse_sign_wire {
        c.x(&parity); // fused parity -> f = NOT(sgn XOR parity)
        if canonical_lambda {
            controlled_field_neg_canonical(c, &parity, &temp);
        } else {
            controlled_field_neg(c, &parity, &temp);
        }
        for (g, q) in lam_ghosts.into_iter().zip(temp.iter()) {
            c.resolve_ghost(g, q);
        }
        if canonical_lambda {
            controlled_field_neg_canonical(c, &parity, &temp);
        } else {
            controlled_field_neg(c, &parity, &temp);
        }
        c.x(&parity);
    } else {
        let sgn = sgn.as_ref().unwrap();
        let f = c.alloc_qreg("shpzcan.negf");
        c.cx(sgn, &f);
        c.cx(&parity, &f);
        c.x(&f); // f = NOT(sgn XOR parity)
        if canonical_lambda {
            controlled_field_neg_canonical(c, &f, &temp);
        } else {
            controlled_field_neg(c, &f, &temp);
        }
        for (g, q) in lam_ghosts.into_iter().zip(temp.iter()) {
            c.resolve_ghost(g, q); // exorcize lambda (temp == lambda's value)
        }
        if canonical_lambda {
            controlled_field_neg_canonical(c, &f, &temp);
        } else {
            controlled_field_neg(c, &f, &temp);
        }
        c.x(&f);
        c.cx(&parity, &f);
        c.cx(sgn, &f); // uncompute f
        c.zero_and_free(f);
    }
    if canonical_lambda {
        mod_mul_canonical_mbu_undo(c, &temp, &ccb[..257], &dy);
    } else {
        mod_mul_rfold_mbu_undo(c, &temp, &ccb[..257], &dy);
    }
    for q in temp {
        c.zero_and_free(q);
    }
    shrunken_pz_resize(c, &mut ccb, cb_w, "cb");

    let released_reverse_dy_top = canonical_passenger_top_lifetime_enabled()
        .then(|| release_canonical_passenger_top(c, &mut dy, "cancel-reverse new_dy"));

    // --- re-create the pack, backward inversion (restore B=|new_dx|) ---
    aa = c.alloc_qreg_bits("shpzcan.A", ta);
    dx = c.alloc_qreg_bits("shpzcan.B", tb);
    c.x(&dx[0]);
    cca = c.alloc_qreg_bits("shpzcan.ca", tca);
    load_p(c, &cca);
    qq = c.alloc_qreg_bits("shpzcan.q", tq);
    if let Some(saved) = saved_affine_counter.as_mut() {
        q949_counter_import(c, &cca, &counter[0], saved);
    }
    shrunken_pz_invert_backward(
        c, &mut aa, &mut dx, &mut cca, &mut ccb, &mut qq, &counter, &parity, &s_rot, off,
    );

    // --- free the clean inversion ancillas (S_0: A=p, ca=0, cb=1, q=0) ---
    if !reuse_sign_wire {
        c.x(&parity);
    }
    c.x(&ccb[0]);
    load_p(c, &aa);
    for q in aa.into_iter().chain(cca).chain(ccb).chain(qq) {
        c.zero_and_free(q);
    }
    if let Some(off) = off_owned {
        c.zero_and_free(off);
    }
    for q in s_rot.into_iter().chain(counter) {
        c.zero_and_free(q);
    }
    if let Some(released) = released_reverse_dy_top {
        restore_canonical_passenger_top(c, &mut dy, released, "cancel-reverse new_dy");
    }

    // --- un-sign-adjust: |new_dx| -> new_dx, uncompute sign state ---
    shrunken_pz_resize(c, &mut dx, 257, "dx");
    if reuse_sign_wire {
        c.x(&parity);
        controlled_field_neg(c, &parity, &dx);
        compare_geq_const(c, &dx, &half_bytes, &parity);
        c.zero_and_free(parity);
    } else {
        let sgn = sgn.unwrap();
        controlled_field_neg(c, &sgn, &dx);
        compare_geq_const(c, &dx, &half_bytes, &sgn);
        c.zero_and_free(sgn);
        c.zero_and_free(parity);
    }

    (dx, dy)
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct GatedCompareExhaustiveReport {
    pub widths_checked: usize,
    pub comparator_states_checked: usize,
    pub gate_hold_states_checked: usize,
    pub borrowed_comparator_states_checked: usize,
    pub borrowed_gate_hold_states_checked: usize,
    pub max_comparator_extra_qubits: usize,
    pub max_gate_hold_extra_qubits: usize,
    pub max_borrowed_comparator_extra_qubits: usize,
    pub max_borrowed_gate_hold_extra_qubits: usize,
}

/// Exhaustively verify the active-gated comparator and `gate_hold` skeleton for
/// widths one through five over every basis state.
#[doc(hidden)]
pub fn exhaustive_gated_compare_check() -> GatedCompareExhaustiveReport {
    use crate::circuit::{Op, OperationType};

    fn apply(ops: &[Op], mut state: u64) -> u64 {
        let bit = |state: u64, id: u64| ((state >> id) & 1) != 0;
        for op in ops {
            match op.kind {
                OperationType::X => state ^= 1u64 << op.q_target.0,
                OperationType::CX => {
                    if bit(state, op.q_control1.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::CCX => {
                    if bit(state, op.q_control1.0) && bit(state, op.q_control2.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::R => {
                    assert!(!bit(state, op.q_target.0), "freed comparator carry was not zero");
                }
                other => panic!("gated comparator emitted unexpected gate {other:?}"),
            }
        }
        state
    }

    fn word(state: u64, start: usize, width: usize) -> u64 {
        (state >> start) & ((1u64 << width) - 1)
    }

    let mut comparator_states_checked = 0usize;
    let mut gate_hold_states_checked = 0usize;
    let mut borrowed_comparator_states_checked = 0usize;
    let mut borrowed_gate_hold_states_checked = 0usize;
    let mut max_comparator_extra_qubits = 0usize;
    let mut max_gate_hold_extra_qubits = 0usize;
    let mut max_borrowed_comparator_extra_qubits = 0usize;
    let mut max_borrowed_gate_hold_extra_qubits = 0usize;

    for width in 1..=5usize {
        let mut c = Circuit::new();
        let active = c.alloc_qreg("gated-check.active");
        let out = c.alloc_qreg("gated-check.out");
        let v = c.alloc_qreg_bits("gated-check.v", width);
        let u = c.alloc_qreg_bits("gated-check.u", width);
        let vr: Vec<&QReg> = v.iter().collect();
        let ur: Vec<&QReg> = u.iter().collect();
        borrow_compare_gated_refs(&mut c, &vr, &ur, &active, &out);
        let external = 2 * width + 2;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_comparator_extra_qubits = max_comparator_extra_qubits.max(extra);
        assert_eq!(extra, 1, "width={width}: gated comparator peak changed");

        for input in 0..(1u64 << external) {
            comparator_states_checked += 1;
            let active_pre = input & 1;
            let out_pre = (input >> 1) & 1;
            let v_pre = word(input, 2, width);
            let u_pre = word(input, 2 + width, width);
            let got = apply(&builder.ops, input);
            let expected_out = out_pre ^ (active_pre & u64::from(v_pre < u_pre));
            assert_eq!(got & 1, active_pre, "width={width}: active changed");
            assert_eq!((got >> 1) & 1, expected_out, "width={width} input={input}");
            assert_eq!(word(got, 2, width), v_pre, "width={width}: v changed");
            assert_eq!(word(got, 2 + width, width), u_pre, "width={width}: u changed");
        }

        let mut c = Circuit::new();
        let active = c.alloc_qreg("borrowed-check.active");
        let out = c.alloc_qreg("borrowed-check.out");
        let carry = c.alloc_qreg("borrowed-check.carry");
        let v = c.alloc_qreg_bits("borrowed-check.v", width);
        let u = c.alloc_qreg_bits("borrowed-check.u", width);
        let vr: Vec<&QReg> = v.iter().collect();
        let ur: Vec<&QReg> = u.iter().collect();
        borrow_compare_gated_refs_with_carry(&mut c, &vr, &ur, &active, &out, &carry);
        let external = 2 * width + 3;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_borrowed_comparator_extra_qubits =
            max_borrowed_comparator_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: borrowed comparator allocated");

        for input in 0..(1u64 << external) {
            if (input >> 2) & 1 != 0 {
                continue;
            }
            borrowed_comparator_states_checked += 1;
            let active_pre = input & 1;
            let out_pre = (input >> 1) & 1;
            let v_pre = word(input, 3, width);
            let u_pre = word(input, 3 + width, width);
            let got = apply(&builder.ops, input);
            let expected_out = out_pre ^ (active_pre & u64::from(v_pre < u_pre));
            assert_eq!(got & 1, active_pre, "width={width}: active changed");
            assert_eq!((got >> 1) & 1, expected_out, "width={width} input={input}");
            assert_eq!((got >> 2) & 1, 0, "width={width}: carry not restored");
            assert_eq!(word(got, 3, width), v_pre, "width={width}: v changed");
            assert_eq!(word(got, 3 + width, width), u_pre, "width={width}: u changed");
        }

        let mut c = Circuit::new();
        let active = c.alloc_qreg("gate-hold-check.active");
        let g = c.alloc_qreg("gate-hold-check.g");
        let body = c.alloc_qreg("gate-hold-check.body");
        let x = c.alloc_qreg_bits("gate-hold-check.x", width);
        let y = c.alloc_qreg_bits("gate-hold-check.y", width);
        gate_hold(&mut c, &x, &y, &active, &g, None, |c, gate| {
            c.cx(gate, &body)
        });
        let external = 2 * width + 3;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_gate_hold_extra_qubits = max_gate_hold_extra_qubits.max(extra);
        assert_eq!(extra, 1, "width={width}: gate_hold peak changed");

        for input in 0..(1u64 << external) {
            gate_hold_states_checked += 1;
            let active_pre = input & 1;
            let g_pre = (input >> 1) & 1;
            let body_pre = (input >> 2) & 1;
            let x_pre = word(input, 3, width);
            let y_pre = word(input, 3 + width, width);
            let got = apply(&builder.ops, input);
            let gate = g_pre ^ (active_pre & u64::from(x_pre < y_pre));
            assert_eq!(got & 1, active_pre, "width={width}: active changed");
            assert_eq!((got >> 1) & 1, g_pre, "width={width}: g not restored");
            assert_eq!((got >> 2) & 1, body_pre ^ gate, "width={width}: body mismatch");
            assert_eq!(word(got, 3, width), x_pre, "width={width}: x changed");
            assert_eq!(word(got, 3 + width, width), y_pre, "width={width}: y changed");
        }

        let mut c = Circuit::new();
        let active = c.alloc_qreg("borrowed-hold.active");
        let g = c.alloc_qreg("borrowed-hold.g");
        let body = c.alloc_qreg("borrowed-hold.body");
        let carry = c.alloc_qreg("borrowed-hold.carry");
        let x = c.alloc_qreg_bits("borrowed-hold.x", width);
        let y = c.alloc_qreg_bits("borrowed-hold.y", width);
        gate_hold(
            &mut c,
            &x,
            &y,
            &active,
            &g,
            Some(&carry),
            |c, gate| c.cx(gate, &body),
        );
        let external = 2 * width + 4;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_borrowed_gate_hold_extra_qubits = max_borrowed_gate_hold_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: borrowed gate_hold allocated");

        for input in 0..(1u64 << external) {
            if (input >> 3) & 1 != 0 {
                continue;
            }
            borrowed_gate_hold_states_checked += 1;
            let active_pre = input & 1;
            let g_pre = (input >> 1) & 1;
            let body_pre = (input >> 2) & 1;
            let x_pre = word(input, 4, width);
            let y_pre = word(input, 4 + width, width);
            let got = apply(&builder.ops, input);
            let gate = g_pre ^ (active_pre & u64::from(x_pre < y_pre));
            assert_eq!(got & 1, active_pre, "width={width}: active changed");
            assert_eq!((got >> 1) & 1, g_pre, "width={width}: g not restored");
            assert_eq!((got >> 2) & 1, body_pre ^ gate, "width={width}: body mismatch");
            assert_eq!((got >> 3) & 1, 0, "width={width}: carry not restored");
            assert_eq!(word(got, 4, width), x_pre, "width={width}: x changed");
            assert_eq!(word(got, 4 + width, width), y_pre, "width={width}: y changed");
        }
    }

    GatedCompareExhaustiveReport {
        widths_checked: 5,
        comparator_states_checked,
        gate_hold_states_checked,
        borrowed_comparator_states_checked,
        borrowed_gate_hold_states_checked,
        max_comparator_extra_qubits,
        max_gate_hold_extra_qubits,
        max_borrowed_comparator_extra_qubits,
        max_borrowed_gate_hold_extra_qubits,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q948DirectHclzRoundtripReport {
    pub widths_checked: usize,
    pub window_pairs_checked: usize,
    pub update_active_states_checked: usize,
    pub update_inactive_states_checked: usize,
    pub parity_active_states_checked: usize,
    pub parity_inactive_states_checked: usize,
    pub phase_cleanup_states_checked: usize,
    pub ancilla_cleanup_states_checked: usize,
    pub reset_operations_checked: usize,
    pub phase_sensitive_operations_observed: usize,
    pub max_update_extra_qubits: usize,
    pub max_parity_extra_qubits: usize,
}

/// Exhaustively check the zero-allocation update and parity bodies used by the
/// Q948 peak guard. Every checked circuit is composed with its inverse, every
/// externally borrowed lane is compared literally, and resets are accepted
/// only when their target is zero. The gate-set audit rejects phase operations.
#[doc(hidden)]
pub fn q948_direct_hclz_roundtrip_check() -> Q948DirectHclzRoundtripReport {
    use crate::circuit::{Op, OperationType};

    fn apply(ops: &[Op], mut state: u64, resets_checked: &mut usize) -> u64 {
        let bit = |state: u64, id: u64| ((state >> id) & 1) != 0;
        for op in ops {
            match op.kind {
                OperationType::X => state ^= 1u64 << op.q_target.0,
                OperationType::CX => {
                    if bit(state, op.q_control1.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::CCX => {
                    if bit(state, op.q_control1.0) && bit(state, op.q_control2.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::R => {
                    assert!(!bit(state, op.q_target.0), "Q948 direct HCLZ reset nonzero");
                    *resets_checked += 1;
                }
                other => panic!("Q948 direct HCLZ proof emitted phase-sensitive gate {other:?}"),
            }
        }
        state
    }

    fn word(state: u64, start: usize, width: usize) -> u64 {
        (state >> start) & ((1u64 << width) - 1)
    }

    let mut window_pairs_checked = 0usize;
    let mut update_active_states_checked = 0usize;
    let mut update_inactive_states_checked = 0usize;
    let mut parity_active_states_checked = 0usize;
    let mut parity_inactive_states_checked = 0usize;
    let mut reset_operations_checked = 0usize;
    let mut max_update_extra_qubits = 0usize;
    let mut max_parity_extra_qubits = 0usize;

    for width in 1..=3usize {
        for lo_a in 0..width {
            for lo_b in 0..width {
                window_pairs_checked += 1;

                let mut update = Circuit::new();
                let active = update.alloc_qreg("q948-direct-update.active");
                let selector = update.alloc_qreg("q948-direct-update.selector");
                let target = update.alloc_qreg_bits("q948-direct-update.target", 3);
                let target_refs: Vec<&QReg> = target.iter().collect();
                let a = update.alloc_qreg_bits("q948-direct-update.a", width);
                let b = update.alloc_qreg_bits("q948-direct-update.b", width);
                let extra = update.alloc_qreg_bits("q948-direct-update.extra", 2);
                let extra_refs: Vec<&QReg> = extra.iter().collect();
                direct_bitlen_diff_update(
                    &mut update,
                    &a,
                    &b,
                    lo_a,
                    lo_b,
                    &target_refs,
                    &active,
                    &selector,
                    false,
                    &extra_refs,
                );
                direct_bitlen_diff_update(
                    &mut update,
                    &a,
                    &b,
                    lo_a,
                    lo_b,
                    &target_refs,
                    &active,
                    &selector,
                    true,
                    &extra_refs,
                );
                let update_external = 7 + 2 * width;
                let update_builder = update.into_builder();
                let update_extra = update_builder.peak_qubits as usize - update_external;
                max_update_extra_qubits = max_update_extra_qubits.max(update_extra);
                assert_eq!(update_extra, 0, "Q948 direct update allocated a lane");
                let update_a_start = 5;
                let update_b_start = update_a_start + width;
                for input in 0..(1u64 << update_external) {
                    assert!(update_external < 64);
                    if (input >> 1) & 1 != 0 {
                        continue;
                    }
                    let active_pre = input & 1;
                    let a_pre = word(input, update_a_start, width);
                    let b_pre = word(input, update_b_start, width);
                    if active_pre == 1
                        && ((a_pre >> lo_a) == 0 || (b_pre >> lo_b) == 0)
                    {
                        continue;
                    }
                    if active_pre == 1 {
                        update_active_states_checked += 1;
                    } else {
                        update_inactive_states_checked += 1;
                    }
                    let got = apply(
                        &update_builder.ops,
                        input,
                        &mut reset_operations_checked,
                    );
                    assert_eq!(
                        got, input,
                        "Q948 direct update roundtrip width={width} lo_a={lo_a} lo_b={lo_b} input={input}"
                    );
                }

                let mut parity = Circuit::new();
                let active = parity.alloc_qreg("q948-direct-parity.active");
                let out = parity.alloc_qreg("q948-direct-parity.out");
                let a = parity.alloc_qreg_bits("q948-direct-parity.a", width);
                let b = parity.alloc_qreg_bits("q948-direct-parity.b", width);
                let extra = parity.alloc_qreg_bits("q948-direct-parity.extra", 2);
                let extra_refs: Vec<&QReg> = extra.iter().collect();
                direct_bitlen_diff_parity(
                    &mut parity,
                    &a,
                    &b,
                    lo_a,
                    lo_b,
                    &out,
                    &active,
                    &extra_refs,
                );
                direct_bitlen_diff_parity(
                    &mut parity,
                    &a,
                    &b,
                    lo_a,
                    lo_b,
                    &out,
                    &active,
                    &extra_refs,
                );
                let parity_external = 4 + 2 * width;
                let parity_builder = parity.into_builder();
                let parity_extra = parity_builder.peak_qubits as usize - parity_external;
                max_parity_extra_qubits = max_parity_extra_qubits.max(parity_extra);
                assert_eq!(parity_extra, 0, "Q948 direct parity allocated a lane");
                let parity_a_start = 2;
                let parity_b_start = parity_a_start + width;
                for input in 0..(1u64 << parity_external) {
                    let active_pre = input & 1;
                    let a_pre = word(input, parity_a_start, width);
                    let b_pre = word(input, parity_b_start, width);
                    if active_pre == 1
                        && ((a_pre >> lo_a) == 0 || (b_pre >> lo_b) == 0)
                    {
                        continue;
                    }
                    if active_pre == 1 {
                        parity_active_states_checked += 1;
                    } else {
                        parity_inactive_states_checked += 1;
                    }
                    let got = apply(
                        &parity_builder.ops,
                        input,
                        &mut reset_operations_checked,
                    );
                    assert_eq!(
                        got, input,
                        "Q948 direct parity roundtrip width={width} lo_a={lo_a} lo_b={lo_b} input={input}"
                    );
                }
            }
        }
    }

    let cleanup_states_checked = update_active_states_checked
        + update_inactive_states_checked
        + parity_active_states_checked
        + parity_inactive_states_checked;
    Q948DirectHclzRoundtripReport {
        widths_checked: 3,
        window_pairs_checked,
        update_active_states_checked,
        update_inactive_states_checked,
        parity_active_states_checked,
        parity_inactive_states_checked,
        phase_cleanup_states_checked: cleanup_states_checked,
        ancilla_cleanup_states_checked: cleanup_states_checked,
        reset_operations_checked,
        phase_sensitive_operations_observed: 0,
        max_update_extra_qubits,
        max_parity_extra_qubits,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct SelectiveBorrowExhaustiveReport {
    pub bitlen_widths_checked: usize,
    pub bitlen_states_checked: usize,
    pub bitlen_parity_states_checked: usize,
    pub counter_gate_widths_checked: usize,
    pub counter_gate_states_checked: usize,
    pub done_widths_checked: usize,
    pub done_states_checked: usize,
    pub demux_widths_checked: usize,
    pub demux_states_checked: usize,
    pub swap_widths_checked: usize,
    pub swap_states_checked: usize,
    pub max_bitlen_extra_qubits: usize,
    pub max_bitlen_parity_extra_qubits: usize,
    pub max_counter_gate_extra_qubits: usize,
    pub max_done_extra_qubits: usize,
    pub max_demux_extra_qubits: usize,
    pub max_swap_extra_qubits: usize,
}

/// Exhaustively verify the actual borrowed demultiplexer and promised-support
/// swap circuits on small basis spaces. The caller must enable the sealed Q959
/// route so this exercises the production branches.
#[doc(hidden)]
pub fn exhaustive_selective_borrow_check() -> SelectiveBorrowExhaustiveReport {
    use crate::circuit::{Op, OperationType};

    assert!(lowq_q959_selective_borrow_enabled());

    fn apply(ops: &[Op], mut state: u64) -> u64 {
        let bit = |state: u64, id: u64| ((state >> id) & 1) != 0;
        for op in ops {
            match op.kind {
                OperationType::X => state ^= 1u64 << op.q_target.0,
                OperationType::CX => {
                    if bit(state, op.q_control1.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::CCX => {
                    if bit(state, op.q_control1.0) && bit(state, op.q_control2.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::R => {
                    assert!(!bit(state, op.q_target.0), "borrowed lane was not zero");
                }
                other => panic!("selective-borrow proof emitted unexpected gate {other:?}"),
            }
        }
        state
    }

    fn word(state: u64, start: usize, width: usize) -> u64 {
        (state >> start) & ((1u64 << width) - 1)
    }

    let mut demux_states_checked = 0usize;
    let mut swap_states_checked = 0usize;
    let mut bitlen_states_checked = 0usize;
    let mut bitlen_parity_states_checked = 0usize;
    let mut counter_gate_states_checked = 0usize;
    let mut done_states_checked = 0usize;
    let mut max_bitlen_extra_qubits = 0usize;
    let mut max_bitlen_parity_extra_qubits = 0usize;
    let mut max_counter_gate_extra_qubits = 0usize;
    let mut max_done_extra_qubits = 0usize;
    let mut max_demux_extra_qubits = 0usize;
    let mut max_swap_extra_qubits = 0usize;

    for width in 1..=3usize {
        for lo_a in 0..width {
            for lo_b in 0..width {
                for subtract_diff in [false, true] {
                    let mut c = Circuit::new();
                    let active = c.alloc_qreg("bitlen-check.active");
                    let gate = c.alloc_qreg("bitlen-check.gate");
                    let target = c.alloc_qreg_bits("bitlen-check.target", 3);
                    let target_refs: Vec<&QReg> = target.iter().collect();
                    let a = c.alloc_qreg_bits("bitlen-check.a", width);
                    let b = c.alloc_qreg_bits("bitlen-check.b", width);
                    let extra = c.alloc_qreg_bits("bitlen-check.extra", 2);
                    let extra_refs: Vec<&QReg> = extra.iter().collect();
                    direct_bitlen_diff_update(
                        &mut c,
                        &a,
                        &b,
                        lo_a,
                        lo_b,
                        &target_refs,
                        &active,
                        &gate,
                        subtract_diff,
                        &extra_refs,
                    );
                    let external = 7 + 2 * width;
                    let builder = c.into_builder();
                    let added = builder.peak_qubits as usize - external;
                    max_bitlen_extra_qubits = max_bitlen_extra_qubits.max(added);
                    assert_eq!(
                        added, 0,
                        "width={width} lo_a={lo_a} lo_b={lo_b}: direct bitlen allocated"
                    );

                    let target_start = 2;
                    let a_start = target_start + 3;
                    let b_start = a_start + width;
                    let target_mask = 0b111u64;
                    for input in 0..(1u64 << external) {
                        if (input >> 1) & 1 != 0 {
                            continue;
                        }
                        let a_pre = word(input, a_start, width);
                        let b_pre = word(input, b_start, width);
                        if (a_pre >> lo_a) == 0 || (b_pre >> lo_b) == 0 {
                            continue;
                        }
                        bitlen_states_checked += 1;
                        let active_pre = input & 1;
                        let target_pre = word(input, target_start, 3);
                        let a_len = 64 - a_pre.leading_zeros() as u64;
                        let b_len = 64 - b_pre.leading_zeros() as u64;
                        let delta = if subtract_diff {
                            b_len.wrapping_sub(a_len)
                        } else {
                            a_len.wrapping_sub(b_len)
                        };
                        let target_post =
                            target_pre.wrapping_add(active_pre * delta) & target_mask;
                        let expected = (input & !(target_mask << target_start))
                            | (target_post << target_start);
                        let got = apply(&builder.ops, input);
                        assert_eq!(
                            got, expected,
                            "bitlen width={width} lo_a={lo_a} lo_b={lo_b} input={input}"
                        );
                    }
                }
            }
        }
    }

    for width in 1..=3usize {
        for lo_a in 0..width {
            for lo_b in 0..width {
                let mut c = Circuit::new();
                let active = c.alloc_qreg("bitlen-parity-check.active");
                let out = c.alloc_qreg("bitlen-parity-check.out");
                let a = c.alloc_qreg_bits("bitlen-parity-check.a", width);
                let b = c.alloc_qreg_bits("bitlen-parity-check.b", width);
                let extra = c.alloc_qreg_bits("bitlen-parity-check.extra", 2);
                let extra_refs: Vec<&QReg> = extra.iter().collect();
                direct_bitlen_diff_parity(
                    &mut c,
                    &a,
                    &b,
                    lo_a,
                    lo_b,
                    &out,
                    &active,
                    &extra_refs,
                );
                let external = 4 + 2 * width;
                let builder = c.into_builder();
                let added = builder.peak_qubits as usize - external;
                max_bitlen_parity_extra_qubits =
                    max_bitlen_parity_extra_qubits.max(added);
                assert_eq!(
                    added, 0,
                    "width={width} lo_a={lo_a} lo_b={lo_b}: direct parity allocated"
                );

                let a_start = 2;
                let b_start = a_start + width;
                for input in 0..(1u64 << external) {
                    let active_pre = input & 1;
                    let a_pre = word(input, a_start, width);
                    let b_pre = word(input, b_start, width);
                    if active_pre == 1 && ((a_pre >> lo_a) == 0 || (b_pre >> lo_b) == 0) {
                        continue;
                    }
                    bitlen_parity_states_checked += 1;
                    let a_len = 64 - a_pre.leading_zeros() as u64;
                    let b_len = 64 - b_pre.leading_zeros() as u64;
                    let expected = input ^ (active_pre * ((a_len ^ b_len) & 1) << 1);
                    let got = apply(&builder.ops, input);
                    assert_eq!(
                        got, expected,
                        "bitlen parity width={width} lo_a={lo_a} lo_b={lo_b} input={input}"
                    );
                }
            }
        }
    }

    for width in 1..=3usize {
        let mut c = Circuit::new();
        let parity = c.alloc_qreg("counter-gate.parity");
        let g = c.alloc_qreg("counter-gate.g");
        let s_rot = c.alloc_qreg_bits("counter-gate.s", 2);
        let body = c.alloc_qreg("counter-gate.body");
        let x = c.alloc_qreg_bits("counter-gate.x", width);
        let y = c.alloc_qreg_bits("counter-gate.y", width);
        let counter = c.alloc_qreg_bits("counter-gate.counter", 2);
        let extra = c.alloc_qreg_bits("counter-gate.extra", 2);
        let candidates: Vec<&QReg> = x
            .iter()
            .chain(y.iter())
            .chain(counter.iter())
            .chain(extra.iter())
            .chain(std::iter::once(&body))
            .chain(std::iter::once(&parity))
            .chain(s_rot.iter())
            .chain(std::iter::once(&g))
            .collect();
        gate_hold_counter_zero(
            &mut c,
            &x,
            &y,
            &counter,
            &parity,
            &s_rot,
            &g,
            &candidates,
            |c, gate| c.cx(gate, &body),
        );
        let external = 9 + 2 * width;
        let builder = c.into_builder();
        let added = builder.peak_qubits as usize - external;
        max_counter_gate_extra_qubits = max_counter_gate_extra_qubits.max(added);
        assert_eq!(added, 0, "width={width}: counter gate allocated");

        let x_start = 5;
        let y_start = x_start + width;
        let counter_start = y_start + width;
        for input in 0..(1u64 << external) {
            if input & 0b1110 != 0 {
                continue;
            }
            counter_gate_states_checked += 1;
            let x_pre = word(input, x_start, width);
            let y_pre = word(input, y_start, width);
            let counter_pre = word(input, counter_start, 2);
            let gate_pre = u64::from(counter_pre == 0 && x_pre < y_pre);
            let expected = input ^ (gate_pre << 4);
            let got = apply(&builder.ops, input);
            assert_eq!(got, expected, "counter gate width={width} input={input}");
        }
    }

    for width in 1..=3usize {
        for inverse in [false, true] {
            let mut c = Circuit::new();
            let off = c.alloc_qreg("done-check.off");
            let s_rot = c.alloc_qreg_bits("done-check.s", 2);
            let aa = c.alloc_qreg_bits("done-check.a", width);
            let qq = c.alloc_qreg_bits("done-check.q", 2);
            let counter = c.alloc_qreg_bits("done-check.counter", 2);
            let extra = c.alloc_qreg_bits("done-check.extra", 2);
            let candidates: Vec<&QReg> = aa
                .iter()
                .chain(qq.iter())
                .chain(counter.iter())
                .chain(extra.iter())
                .chain(s_rot.iter())
                .chain(std::iter::once(&off))
                .collect();
            done_counter_fn(
                &mut c,
                &aa,
                &qq,
                &counter,
                &s_rot,
                &off,
                &candidates,
                inverse,
            );
            let external = 9 + width;
            let builder = c.into_builder();
            let added = builder.peak_qubits as usize - external;
            max_done_extra_qubits = max_done_extra_qubits.max(added);
            assert_eq!(added, 0, "width={width}: done counter allocated");

            let a_start = 3;
            let q_start = a_start + width;
            let counter_start = q_start + 2;
            for input in 0..(1u64 << external) {
                if input & 0b111 != 0 {
                    continue;
                }
                let a_pre = word(input, a_start, width);
                let q_pre = word(input, q_start, 2);
                let counter_pre = word(input, counter_start, 2);
                let conv = a_pre == 0 && q_pre == 0;
                if inverse {
                    if (counter_pre == 0) != !conv {
                        continue;
                    }
                } else if (counter_pre > 0 && !conv) || (counter_pre == 3 && conv) {
                    continue;
                }
                done_states_checked += 1;
                let counter_post = if inverse {
                    counter_pre.saturating_sub(u64::from(counter_pre > 0))
                } else {
                    counter_pre + u64::from(conv)
                };
                let mask = 0b11u64 << counter_start;
                let expected = (input & !mask) | (counter_post << counter_start);
                let got = apply(&builder.ops, input);
                assert_eq!(got, expected, "done width={width} inverse={inverse} input={input}");
            }
        }
    }

    for width in 1..=3usize {
        let mut c = Circuit::new();
        let active = c.alloc_qreg("demux-check.active");
        let gate = c.alloc_qreg("demux-check.gate");
        let s = c.alloc_qreg_bits("demux-check.s", width);
        let q = c.alloc_qreg_bits("demux-check.q", 1usize << width);
        let lender_regs = c.alloc_qreg_bits("demux-check.lender", width.saturating_sub(1));
        let lenders: Vec<&QReg> = lender_regs.iter().collect();
        let s_refs: Vec<&QReg> = s.iter().collect();
        set_bit_at_s_gated(&mut c, &q, &s_refs, &active, &gate, &lenders);
        let external = 2 + width + (1usize << width) + lender_regs.len();
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_demux_extra_qubits = max_demux_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: borrowed demux allocated");

        let s_start = 2;
        let q_start = s_start + width;
        for input in 0..(1u64 << external) {
            if (input >> 1) & 1 != 0 {
                continue;
            }
            demux_states_checked += 1;
            let active_pre = input & 1;
            let selected = word(input, s_start, width) as usize;
            let expected = input ^ (active_pre << (q_start + selected));
            let got = apply(&builder.ops, input);
            assert_eq!(got, expected, "demux width={width} input={input}");
        }
    }

    for width in 1..=2usize {
        let mut c = Circuit::new();
        let _active = c.alloc_qreg("swap-check.spectator");
        let parity = c.alloc_qreg("swap-check.parity");
        let off = c.alloc_qreg("swap-check.off");
        let s_rot = c.alloc_qreg_bits("swap-check.s", 2);
        let aa = c.alloc_qreg_bits("swap-check.a", width);
        let bb = c.alloc_qreg_bits("swap-check.b", width);
        let cca = c.alloc_qreg_bits("swap-check.ca", width);
        let ccb = c.alloc_qreg_bits("swap-check.cb", width);
        let qq = c.alloc_qreg_bits("swap-check.q", width);
        let counter = c.alloc_qreg_bits("swap-check.counter", 1);
        borrowed_swap_in_place(
            &mut c, &aa, &bb, &cca, &ccb, &qq, &counter, &parity, &s_rot, &off,
        );
        let external = 6 + 5 * width;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_swap_extra_qubits = max_swap_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: borrowed swap allocated");

        let a_start = 5;
        let b_start = a_start + width;
        let ca_start = b_start + width;
        let cb_start = ca_start + width;
        let q_start = cb_start + width;
        let counter_start = q_start + width;
        let mask = (1u64 << width) - 1;
        for input in 0..(1u64 << external) {
            if input & 0b1_1100 != 0 {
                continue;
            }
            let a_pre = word(input, a_start, width);
            let b_pre = word(input, b_start, width);
            let q_pre = word(input, q_start, width);
            let counter_pre = word(input, counter_start, 1);
            let gate = counter_pre == 0 && q_pre == 0 && a_pre != 0;
            if gate && b_pre == 0 {
                continue;
            }
            swap_states_checked += 1;
            let mut expected = input;
            if gate {
                let ca_pre = word(input, ca_start, width);
                let cb_pre = word(input, cb_start, width);
                expected &= !((mask << a_start)
                    | (mask << b_start)
                    | (mask << ca_start)
                    | (mask << cb_start));
                expected |= b_pre << a_start;
                expected |= a_pre << b_start;
                expected |= cb_pre << ca_start;
                expected |= ca_pre << cb_start;
                expected ^= 1 << 1;
            }
            let got = apply(&builder.ops, input);
            assert_eq!(got, expected, "swap width={width} input={input}");
        }
    }

    SelectiveBorrowExhaustiveReport {
        bitlen_widths_checked: 3,
        bitlen_states_checked,
        bitlen_parity_states_checked,
        counter_gate_widths_checked: 3,
        counter_gate_states_checked,
        done_widths_checked: 3,
        done_states_checked,
        demux_widths_checked: 3,
        demux_states_checked,
        swap_widths_checked: 2,
        swap_states_checked,
        max_bitlen_extra_qubits,
        max_bitlen_parity_extra_qubits,
        max_counter_gate_extra_qubits,
        max_done_extra_qubits,
        max_demux_extra_qubits,
        max_swap_extra_qubits,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct OffBorrowExhaustiveReport {
    pub body_widths_checked: usize,
    pub forward_states_checked: usize,
    pub reverse_states_checked: usize,
    pub roundtrip_states_checked: usize,
    pub composed_widths_checked: usize,
    pub composed_states_checked: usize,
    pub composed_roundtrip_states_checked: usize,
    pub demux_widths_checked: usize,
    pub demux_states_checked: usize,
    pub done_widths_checked: usize,
    pub done_states_checked: usize,
    pub swap_widths_checked: usize,
    pub swap_states_checked: usize,
    pub max_body_extra_qubits: usize,
    pub max_composed_extra_qubits: usize,
    pub max_demux_extra_qubits: usize,
    pub max_done_extra_qubits: usize,
    pub max_swap_extra_qubits: usize,
}

/// Exhaustively verify the Q956 support contract on small basis spaces.
/// Active branches require the borrowed counter lane to be zero; inactive
/// branches deliberately cover both lane values and must remain unchanged.
/// The body checks exercise the production masked shift/increment primitives
/// in both directions and as a complete forward/reverse cleanup pair.
#[doc(hidden)]
pub fn exhaustive_off_borrow_check() -> OffBorrowExhaustiveReport {
    use crate::circuit::{Op, OperationType};

    assert!(lowq_q956_off_borrow_enabled());

    fn apply(ops: &[Op], mut state: u64) -> u64 {
        let bit = |state: u64, id: u64| ((state >> id) & 1) != 0;
        for op in ops {
            match op.kind {
                OperationType::X => state ^= 1u64 << op.q_target.0,
                OperationType::CX => {
                    if bit(state, op.q_control1.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::CCX => {
                    if bit(state, op.q_control1.0) && bit(state, op.q_control2.0) {
                        state ^= 1u64 << op.q_target.0;
                    }
                }
                OperationType::R => {
                    assert!(!bit(state, op.q_target.0), "Q956 proof freed a nonzero lane");
                }
                other => panic!("Q956 off-borrow proof emitted unexpected gate {other:?}"),
            }
        }
        state
    }

    fn word(state: u64, start: usize, width: usize) -> u64 {
        (state >> start) & ((1u64 << width) - 1)
    }

    let mut forward_states_checked = 0usize;
    let mut reverse_states_checked = 0usize;
    let mut roundtrip_states_checked = 0usize;
    let mut composed_states_checked = 0usize;
    let mut composed_roundtrip_states_checked = 0usize;
    let mut demux_states_checked = 0usize;
    let mut done_states_checked = 0usize;
    let mut swap_states_checked = 0usize;
    let mut max_body_extra_qubits = 0usize;
    let mut max_composed_extra_qubits = 0usize;
    let mut max_demux_extra_qubits = 0usize;
    let mut max_done_extra_qubits = 0usize;
    let mut max_swap_extra_qubits = 0usize;

    for width in 2..=4usize {
        let build = |forward: bool, roundtrip: bool| {
            let mut c = Circuit::new();
            let active = c.alloc_qreg("off-body.active");
            let predicate = c.alloc_qreg("off-body.predicate");
            let off = c.alloc_qreg("off-body.borrowed");
            let s = c.alloc_qreg_bits("off-body.s", 3);
            let value = c.alloc_qreg_bits("off-body.value", width);
            let lender_regs = c.alloc_qreg_bits("off-body.lender", 4);
            let s_refs: Vec<&QReg> = s.iter().collect();
            let candidates: Vec<&QReg> = value
                .iter()
                .chain(s.iter())
                .chain(lender_regs.iter())
                .chain(std::iter::once(&active))
                .chain(std::iter::once(&predicate))
                .chain(std::iter::once(&off))
                .collect();
            let emit_forward = |c: &mut Circuit| {
                c.ccx(&active, &predicate, &off);
                rotate_one_by_off(c, &value, &active, &off, true, &candidates);
                ctrl_inc_by_off(c, &active, &off, &s_refs, &candidates);
                c.ccx(&active, &predicate, &off);
            };
            let emit_reverse = |c: &mut Circuit| {
                c.ccx(&active, &predicate, &off);
                ctrl_dec_by_off(c, &active, &off, &s_refs, &candidates);
                rotate_one_by_off(c, &value, &active, &off, false, &candidates);
                c.ccx(&active, &predicate, &off);
            };
            if forward {
                emit_forward(&mut c);
                if roundtrip {
                    emit_reverse(&mut c);
                }
            } else {
                emit_reverse(&mut c);
            }
            c.into_builder()
        };

        let external = 10 + width;
        let forward = build(true, false);
        let reverse = build(false, false);
        let roundtrip = build(true, true);
        for builder in [&forward, &reverse, &roundtrip] {
            let extra = builder.peak_qubits as usize - external;
            max_body_extra_qubits = max_body_extra_qubits.max(extra);
            assert_eq!(extra, 0, "width={width}: Q956 body allocated a lane");
        }

        let s_start = 3;
        let value_start = 6;
        let s_mask = 0b111u64;
        let value_mask = (1u64 << width) - 1;
        for input in 0..(1u64 << external) {
            let active = input & 1;
            let predicate = (input >> 1) & 1;
            let off = (input >> 2) & 1;
            if active == 1 && off != 0 {
                continue;
            }
            let gate = active & predicate;
            let s_pre = word(input, s_start, 3);
            let value_pre = word(input, value_start, width);

            if gate == 0 || value_pre >> (width - 1) == 0 {
                forward_states_checked += 1;
                let s_post = s_pre.wrapping_add(gate) & s_mask;
                let value_post = (value_pre << gate) & value_mask;
                let expected = (input
                    & !((s_mask << s_start) | (value_mask << value_start)))
                    | (s_post << s_start)
                    | (value_post << value_start);
                assert_eq!(
                    apply(&forward.ops, input),
                    expected,
                    "Q956 forward width={width} input={input}"
                );
                roundtrip_states_checked += 1;
                assert_eq!(
                    apply(&roundtrip.ops, input),
                    input,
                    "Q956 roundtrip width={width} input={input}"
                );
            }

            if gate == 0 || value_pre & 1 == 0 {
                reverse_states_checked += 1;
                let s_post = s_pre.wrapping_sub(gate) & s_mask;
                let value_post = value_pre >> gate;
                let expected = (input
                    & !((s_mask << s_start) | (value_mask << value_start)))
                    | (s_post << s_start)
                    | (value_post << value_start);
                assert_eq!(
                    apply(&reverse.ops, input),
                    expected,
                    "Q956 reverse width={width} input={input}"
                );
            }
        }
    }

    for width in 1..=2usize {
        let build = |roundtrip: bool| {
            let mut c = Circuit::new();
            let parity = c.alloc_qreg("off-composed.parity");
            let g = c.alloc_qreg("off-composed.g");
            let s_rot = c.alloc_qreg_bits("off-composed.srot", 2);
            let predicate = c.alloc_qreg("off-composed.predicate");
            let target = c.alloc_qreg_bits("off-composed.target", 2);
            let value = c.alloc_qreg_bits("off-composed.value", 2);
            let x = c.alloc_qreg_bits("off-composed.x", width);
            let y = c.alloc_qreg_bits("off-composed.y", width);
            let counter = c.alloc_qreg_bits("off-composed.counter", 2);
            let target_refs: Vec<&QReg> = target.iter().collect();
            let candidates: Vec<&QReg> = x
                .iter()
                .chain(y.iter())
                .chain(counter.iter())
                .chain(value.iter())
                .chain(target.iter())
                .chain(std::iter::once(&predicate))
                .chain(std::iter::once(&parity))
                .chain(s_rot.iter())
                .chain(std::iter::once(&g))
                .collect();
            let emit = |c: &mut Circuit, forward: bool| {
                gate_hold_counter_zero(
                    c,
                    &x,
                    &y,
                    &counter,
                    &parity,
                    &s_rot,
                    &g,
                    &candidates,
                    |c, active| {
                        let off = &counter[0];
                        c.ccx(active, &predicate, off);
                        if forward {
                            rotate_one_by_off(c, &value, active, off, true, &candidates);
                            ctrl_inc_by_off(c, active, off, &target_refs, &candidates);
                        } else {
                            ctrl_dec_by_off(c, active, off, &target_refs, &candidates);
                            rotate_one_by_off(c, &value, active, off, false, &candidates);
                        }
                        c.ccx(active, &predicate, off);
                    },
                );
            };
            emit(&mut c, true);
            if roundtrip {
                emit(&mut c, false);
            }
            c.into_builder()
        };

        let external = 11 + 2 * width;
        let forward = build(false);
        let roundtrip = build(true);
        for builder in [&forward, &roundtrip] {
            let extra = builder.peak_qubits as usize - external;
            max_composed_extra_qubits = max_composed_extra_qubits.max(extra);
            assert_eq!(
                extra, 0,
                "width={width}: composed Q956 gate holder allocated a lane"
            );
        }

        let target_start = 5;
        let value_start = 7;
        let x_start = 9;
        let y_start = x_start + width;
        let counter_start = y_start + width;
        for input in 0..(1u64 << external) {
            if input & 0b1110 != 0 {
                continue;
            }
            let predicate = (input >> 4) & 1;
            let target_pre = word(input, target_start, 2);
            let value_pre = word(input, value_start, 2);
            let x_pre = word(input, x_start, width);
            let y_pre = word(input, y_start, width);
            let counter_pre = word(input, counter_start, 2);
            let gate = u64::from(counter_pre == 0 && x_pre < y_pre) * predicate;
            if gate == 1 && value_pre >> 1 != 0 {
                continue;
            }
            composed_states_checked += 1;
            let target_post = target_pre.wrapping_add(gate) & 0b11;
            let value_post = (value_pre << gate) & 0b11;
            let expected = (input & !((0b11 << target_start) | (0b11 << value_start)))
                | (target_post << target_start)
                | (value_post << value_start);
            assert_eq!(
                apply(&forward.ops, input),
                expected,
                "Q956 composed width={width} input={input}"
            );
            composed_roundtrip_states_checked += 1;
            assert_eq!(
                apply(&roundtrip.ops, input),
                input,
                "Q956 composed roundtrip width={width} input={input}"
            );
        }
    }

    for width in 1..=3usize {
        let mut c = Circuit::new();
        let active = c.alloc_qreg("off-demux.active");
        let off = c.alloc_qreg("off-demux.borrowed");
        let s = c.alloc_qreg_bits("off-demux.s", width);
        let q = c.alloc_qreg_bits("off-demux.q", 1usize << width);
        let lender_regs = c.alloc_qreg_bits("off-demux.lender", width);
        let lenders: Vec<&QReg> = lender_regs.iter().collect();
        let s_refs: Vec<&QReg> = s.iter().collect();
        set_bit_at_s_gated(&mut c, &q, &s_refs, &active, &off, &lenders);
        let external = 2 + 2 * width + (1usize << width);
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_demux_extra_qubits = max_demux_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: Q956 demux allocated a lane");

        let s_start = 2;
        let q_start = s_start + width;
        for input in 0..(1u64 << external) {
            let active_pre = input & 1;
            let off_pre = (input >> 1) & 1;
            if active_pre == 1 && off_pre != 0 {
                continue;
            }
            demux_states_checked += 1;
            let selected = word(input, s_start, width) as usize;
            let expected = input ^ (active_pre << (q_start + selected));
            assert_eq!(
                apply(&builder.ops, input),
                expected,
                "Q956 demux width={width} input={input}"
            );
        }
    }

    for width in 1..=2usize {
        for inverse in [false, true] {
            let mut c = Circuit::new();
            let s_rot = c.alloc_qreg_bits("off-done.s", 3);
            let aa = c.alloc_qreg_bits("off-done.a", width);
            let qq = c.alloc_qreg_bits("off-done.q", 2);
            let counter = c.alloc_qreg_bits("off-done.counter", 2);
            let extra = c.alloc_qreg_bits("off-done.extra", 3);
            let off = &counter[0];
            let candidates: Vec<&QReg> = aa
                .iter()
                .chain(qq.iter())
                .chain(counter.iter())
                .chain(extra.iter())
                .chain(s_rot.iter())
                .collect();
            done_counter_fn(
                &mut c,
                &aa,
                &qq,
                &counter,
                &s_rot,
                off,
                &candidates,
                inverse,
            );
            let external = 10 + width;
            let builder = c.into_builder();
            let extra = builder.peak_qubits as usize - external;
            max_done_extra_qubits = max_done_extra_qubits.max(extra);
            assert_eq!(extra, 0, "width={width}: Q956 done allocated a lane");

            let a_start = 3;
            let q_start = a_start + width;
            let counter_start = q_start + 2;
            for input in 0..(1u64 << external) {
                if input & 0b111 != 0 {
                    continue;
                }
                let a_pre = word(input, a_start, width);
                let q_pre = word(input, q_start, 2);
                let counter_pre = word(input, counter_start, 2);
                let conv = a_pre == 0 && q_pre == 0;
                if inverse {
                    if (counter_pre == 0) != !conv {
                        continue;
                    }
                } else if (counter_pre > 0 && !conv) || (counter_pre == 3 && conv) {
                    continue;
                }
                done_states_checked += 1;
                let counter_post = if inverse {
                    counter_pre.saturating_sub(u64::from(counter_pre > 0))
                } else {
                    counter_pre + u64::from(conv)
                };
                let mask = 0b11u64 << counter_start;
                let expected = (input & !mask) | (counter_post << counter_start);
                assert_eq!(
                    apply(&builder.ops, input),
                    expected,
                    "Q956 done width={width} inverse={inverse} input={input}"
                );
            }
        }
    }

    for width in 1..=2usize {
        let mut c = Circuit::new();
        let parity = c.alloc_qreg("off-swap.parity");
        let s_rot = c.alloc_qreg_bits("off-swap.s", 3);
        let aa = c.alloc_qreg_bits("off-swap.a", width);
        let bb = c.alloc_qreg_bits("off-swap.b", width);
        let cca = c.alloc_qreg_bits("off-swap.ca", width);
        let ccb = c.alloc_qreg_bits("off-swap.cb", width);
        let qq = c.alloc_qreg_bits("off-swap.q", width);
        let counter = c.alloc_qreg_bits("off-swap.counter", 1);
        let off = &counter[0];
        borrowed_swap_in_place(
            &mut c, &aa, &bb, &cca, &ccb, &qq, &counter, &parity, &s_rot, off,
        );
        let external = 5 + 5 * width;
        let builder = c.into_builder();
        let extra = builder.peak_qubits as usize - external;
        max_swap_extra_qubits = max_swap_extra_qubits.max(extra);
        assert_eq!(extra, 0, "width={width}: Q956 swap allocated a lane");

        let a_start = 4;
        let b_start = a_start + width;
        let ca_start = b_start + width;
        let cb_start = ca_start + width;
        let q_start = cb_start + width;
        let counter_start = q_start + width;
        let mask = (1u64 << width) - 1;
        for input in 0..(1u64 << external) {
            if input & 0b1110 != 0 {
                continue;
            }
            let a_pre = word(input, a_start, width);
            let b_pre = word(input, b_start, width);
            let q_pre = word(input, q_start, width);
            let counter_pre = word(input, counter_start, 1);
            let gate = counter_pre == 0 && q_pre == 0 && a_pre != 0;
            if gate && b_pre == 0 {
                continue;
            }
            swap_states_checked += 1;
            let mut expected = input;
            if gate {
                let ca_pre = word(input, ca_start, width);
                let cb_pre = word(input, cb_start, width);
                expected &= !((mask << a_start)
                    | (mask << b_start)
                    | (mask << ca_start)
                    | (mask << cb_start));
                expected |= b_pre << a_start;
                expected |= a_pre << b_start;
                expected |= cb_pre << ca_start;
                expected |= ca_pre << cb_start;
                expected ^= 1;
            }
            assert_eq!(
                apply(&builder.ops, input),
                expected,
                "Q956 swap width={width} input={input}"
            );
        }
    }

    OffBorrowExhaustiveReport {
        body_widths_checked: 3,
        forward_states_checked,
        reverse_states_checked,
        roundtrip_states_checked,
        composed_widths_checked: 2,
        composed_states_checked,
        composed_roundtrip_states_checked,
        demux_widths_checked: 3,
        demux_states_checked,
        done_widths_checked: 2,
        done_states_checked,
        swap_widths_checked: 2,
        swap_states_checked,
        max_body_extra_qubits,
        max_composed_extra_qubits,
        max_demux_extra_qubits,
        max_done_extra_qubits,
        max_swap_extra_qubits,
    }
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944CatalyticOperationFailure {
    pub row: usize,
    pub inverse: bool,
    pub operation_index: usize,
    pub phase: String,
    pub operation: Op,
    pub reason: &'static str,
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944CatalyticStreamReport {
    pub row: usize,
    pub inverse: bool,
    pub comparator_width: usize,
    pub source_operations: usize,
    pub source_x: usize,
    pub source_cx: usize,
    pub source_ccx: usize,
    pub source_ccz: usize,
    pub source_toffoli_class: usize,
    pub formal_predicate_mentions: usize,
    pub unconditional_template_operations: usize,
    pub classified_x: usize,
    pub classified_cx: usize,
    pub classified_ccx: usize,
    pub classified_ccz: usize,
    pub classified_operations: usize,
    pub unsupported_operations: usize,
    pub predicate_support_target_checks: usize,
    pub predicate_support_target_conflicts: usize,
    pub disjoint_pair_checks: usize,
    pub disjoint_pair_misses: usize,
    pub projected_x: usize,
    pub projected_cx: usize,
    pub projected_ccx: usize,
    pub projected_ccz: usize,
    pub projected_operations: usize,
    pub projected_toffoli_class: usize,
    pub input_qubits: usize,
    pub peak_qubits: usize,
    pub peak_extra_qubits: usize,
    pub final_active_qubits: usize,
    pub first_failure: Option<Q944CatalyticOperationFailure>,
    pub clean: bool,
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944CatalyticBlockedSiteReport {
    pub phase: &'static str,
    pub direction: &'static str,
    pub row: usize,
    pub stream_index: usize,
    pub clean: bool,
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944CatalyticBlockedCensusReport {
    pub rows_checked: usize,
    pub streams_checked: usize,
    pub sites_checked: usize,
    pub clean_streams: usize,
    pub blocked_streams: usize,
    pub clean_sites: usize,
    pub blocked_sites: usize,
    pub source_operations: usize,
    pub classified_operations: usize,
    pub unsupported_operations: usize,
    pub predicate_support_target_checks: usize,
    pub predicate_support_target_conflicts: usize,
    pub disjoint_pair_checks: usize,
    pub disjoint_pair_misses: usize,
    pub projected_operations: usize,
    pub projected_toffoli_class: usize,
    pub first_failure: Option<Q944CatalyticOperationFailure>,
    pub streams: Vec<Q944CatalyticStreamReport>,
    pub sites: Vec<Q944CatalyticBlockedSiteReport>,
    pub exact_clean: bool,
}

fn q944_op_mentions(op: &Op, lane: QubitId) -> bool {
    op.q_target == lane || op.q_control1 == lane || op.q_control2 == lane
}

fn q944_phase_at(builder: &B, operation_index: usize) -> String {
    let mut phase = "trailmix";
    for &(index, candidate) in &builder.phase_transitions {
        if index > operation_index {
            break;
        }
        phase = candidate;
    }
    phase.to_owned()
}

fn q944_accumulate_cost(
    total: &mut crate::point_add::trailmix_port::inversion::
        q944_dirty_catalytic_predicate::Q944CatalyticGateCounts,
    cost: crate::point_add::trailmix_port::inversion::
        q944_dirty_catalytic_predicate::Q944CatalyticGateCounts,
) {
    total.x += cost.x;
    total.cx += cost.cx;
    total.ccx += cost.ccx;
    total.ccz += cost.ccz;
    total.total += cost.total;
    total.toffoli_class += cost.toffoli_class;
}

/// Emit one exact-width blocked division body with a formal clean predicate,
/// then classify the `active=1` primitive template for dirty-catalytic control.
/// This is an isolated source census; it does not rewrite the production route.
fn q944_catalytic_blocked_stream(row: usize, inverse: bool) -> Q944CatalyticStreamReport {
    use crate::point_add::trailmix_port::inversion::q944_dirty_catalytic_predicate::{
        q944_catalytic_cost, q944_classify_template_op,
        q944_select_catalytic_dirty_pair, Q944CatalyticGateCounts, Q944CatalyticKind,
    };
    use crate::point_add::trailmix_port::inversion::q949_robust_envelope::
        q949_robust_pair_symmetric_widths;
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::shift_bounds;

    assert!([374, 375, 376, 379, 380].contains(&row));
    assert!(lowq_q945_local_hosts_enabled());
    assert!(lowq_q945_dirty_parity_arithmetic_enabled());
    assert!(lowq_q949_affine_counter_enabled());
    assert!(!lowq_q954_srot_counter7_enabled());

    fn rb(bound: usize) -> usize {
        if bound == 0 {
            1
        } else {
            64 - (bound as u64).leading_zeros() as usize
        }
    }

    let widths = q949_robust_pair_symmetric_widths(row);
    let [lo_a, lo_b, _, _, _] = trailmix_register_los_step(row);
    let (shift_bound, _) = shift_bounds(row);
    let mut circ = Circuit::new();
    let a = circ.alloc_qreg_bits("q944.census.a", widths[0]);
    let b = circ.alloc_qreg_bits("q944.census.b", widths[1]);
    let ca = circ.alloc_qreg_bits("q944.census.ca", widths[2]);
    let cb = circ.alloc_qreg_bits("q944.census.cb", widths[3]);
    let q = circ.alloc_qreg_bits("q944.census.q", widths[4]);
    let counter = circ.alloc_qreg_bits("q944.census.counter", trailmix_counter_width());
    let parity = circ.alloc_qreg("q944.census.parity");
    let s_rot = circ.alloc_qreg_bits("q944.census.srot", trailmix_srot_width());
    let formal_active = circ.alloc_qreg("q944.census.formal-active");
    assert_eq!(counter.len(), 1);
    assert_eq!(s_rot.len(), 5);
    let off = &counter[0];
    let extra_lenders: Vec<&QReg> = ca.iter().chain(cb.iter()).collect();
    let reverse_relational = inverse
        && row == BORROWED_ROW_380
        && lowq_reverse_ca255_relational_loan_enabled();
    let transcript_loans = q945_local_hclz_loans(
        row,
        inverse,
        BorrowedTranscriptSubstep::Division,
        &a,
        &b,
        &ca,
        &cb,
        &q,
        &counter,
        off,
    )
    .unwrap_or_else(|| {
        if reverse_relational {
            let loan = borrowed_transcript_loan(
                row,
                inverse,
                BorrowedTranscriptSubstep::Division,
                &a,
                &ca,
                &cb,
                &counter,
                Some(&formal_active),
            );
            BorrowedTranscriptLoans::shared(loan)
        } else {
            BorrowedTranscriptLoans::shared(borrowed_transcript_loan(
                row,
                inverse,
                BorrowedTranscriptSubstep::Division,
                &a,
                &ca,
                &cb,
                &counter,
                None,
            ))
        }
    });
    let q945_carry = q945_narrow_carry(
        row,
        Q945Substep::Division,
        &a,
        &b,
        &ca,
        &cb,
        &q,
        off,
        &parity,
    );
    let input_qubits = circ.b.active_qubits as usize;
    with_arithmetic_srot_view(&s_rot, &counter, |s_rot_view| {
        if inverse {
            division_substep_windowed_inv(
                &mut circ,
                &a,
                &b,
                &q,
                s_rot_view,
                off,
                &formal_active,
                &extra_lenders,
                lo_a,
                lo_b,
                rb(shift_bound),
                q954_ctz_width(row),
                transcript_loans,
                q945_carry,
            );
        } else {
            division_substep_windowed(
                &mut circ,
                &a,
                &b,
                &q,
                s_rot_view,
                off,
                &formal_active,
                &extra_lenders,
                lo_a,
                lo_b,
                rb(shift_bound),
                q954_ctz_width(row),
                transcript_loans,
                q945_carry,
            );
        }
    });
    circ.flush_pending_frees();
    let final_active_qubits = circ.b.active_qubits as usize;
    assert_eq!(final_active_qubits, input_qubits, "Q944 census body leaked qubits");

    let formal_id = QubitId(u64::from(formal_active.id()));
    let candidates: Vec<QubitId> = a
        .iter()
        .chain(b.iter())
        .chain(q.iter())
        .chain(s_rot.iter())
        .map(|lane| QubitId(u64::from(lane.id())))
        .collect();
    // The strict comparator computes `f = !done && (ca < cb)`. A primitive
    // may use these lanes as controls, but it must not change one between the
    // two predicate toggles. The parity lane is only an arbitrary dirty carry,
    // so changing and restoring it is not a change to the predicate itself.
    let predicate_support: Vec<QubitId> = ca
        .iter()
        .chain(cb.iter())
        .chain(counter.iter())
        .map(|lane| QubitId(u64::from(lane.id())))
        .collect();
    let forbidden: Vec<QubitId> = ca
        .iter()
        .chain(cb.iter())
        .chain(counter.iter())
        .chain(std::iter::once(&parity))
        .chain(std::iter::once(&formal_active))
        .map(|lane| QubitId(u64::from(lane.id())))
        .collect();
    let builder = circ.into_builder();
    let source_operations = builder.ops.len();
    let source_x = builder.counted_kind_ops[OperationType::X as usize];
    let source_cx = builder.counted_kind_ops[OperationType::CX as usize];
    let source_ccx = builder.counted_kind_ops[OperationType::CCX as usize];
    let source_ccz = builder.counted_kind_ops[OperationType::CCZ as usize];
    let source_toffoli_class = source_ccx + source_ccz;
    let mut formal_predicate_mentions = 0usize;
    let mut classified = [0usize; 4];
    let mut classified_operations = 0usize;
    let mut unsupported_operations = 0usize;
    let mut predicate_support_target_checks = 0usize;
    let mut predicate_support_target_conflicts = 0usize;
    let mut disjoint_pair_checks = 0usize;
    let mut disjoint_pair_misses = 0usize;
    let mut projected = Q944CatalyticGateCounts::default();
    let mut first_failure = None;

    for (operation_index, operation) in builder.ops.iter().enumerate() {
        formal_predicate_mentions += usize::from(q944_op_mentions(operation, formal_id));
        match q944_classify_template_op(operation, formal_id) {
            Ok(primitive) => {
                classified_operations += 1;
                let kind_index = match primitive.kind {
                    Q944CatalyticKind::X => 0,
                    Q944CatalyticKind::CX => 1,
                    Q944CatalyticKind::CCX => 2,
                    Q944CatalyticKind::CCZ => 3,
                };
                classified[kind_index] += 1;
                predicate_support_target_checks += 1;
                let predicate_support_conflict = primitive.mutable_target != NO_QUBIT
                    && predicate_support.contains(&primitive.mutable_target);
                if predicate_support_conflict {
                    predicate_support_target_conflicts += 1;
                    if first_failure.is_none() {
                        first_failure = Some(Q944CatalyticOperationFailure {
                            row,
                            inverse,
                            operation_index,
                            phase: q944_phase_at(&builder, operation_index),
                            operation: *operation,
                            reason: "mutable-target-overlaps-recomputed-predicate-support",
                        });
                    }
                }
                disjoint_pair_checks += 1;
                if q944_select_catalytic_dirty_pair(&primitive, &candidates, &forbidden).is_none() {
                    disjoint_pair_misses += 1;
                    if first_failure.is_none() {
                        first_failure = Some(Q944CatalyticOperationFailure {
                            row,
                            inverse,
                            operation_index,
                            phase: q944_phase_at(&builder, operation_index),
                            operation: *operation,
                            reason: "no-two-disjoint-long-lived-dirty-lanes",
                        });
                    }
                }
                q944_accumulate_cost(
                    &mut projected,
                    q944_catalytic_cost(widths[2], primitive.kind),
                );
            }
            Err(reject) => {
                unsupported_operations += 1;
                if first_failure.is_none() {
                    first_failure = Some(Q944CatalyticOperationFailure {
                        row,
                        inverse,
                        operation_index,
                        phase: q944_phase_at(&builder, operation_index),
                        operation: *operation,
                        reason: reject.label(),
                    });
                }
            }
        }
    }
    let clean = unsupported_operations == 0
        && predicate_support_target_conflicts == 0
        && disjoint_pair_misses == 0;
    Q944CatalyticStreamReport {
        row,
        inverse,
        comparator_width: widths[2],
        source_operations,
        source_x,
        source_cx,
        source_ccx,
        source_ccz,
        source_toffoli_class,
        formal_predicate_mentions,
        unconditional_template_operations: source_operations - formal_predicate_mentions,
        classified_x: classified[0],
        classified_cx: classified[1],
        classified_ccx: classified[2],
        classified_ccz: classified[3],
        classified_operations,
        unsupported_operations,
        predicate_support_target_checks,
        predicate_support_target_conflicts,
        disjoint_pair_checks,
        disjoint_pair_misses,
        projected_x: projected.x,
        projected_cx: projected.cx,
        projected_ccx: projected.ccx,
        projected_ccz: projected.ccz,
        projected_operations: projected.total,
        projected_toffoli_class: projected.toffoli_class,
        input_qubits,
        peak_qubits: builder.peak_qubits as usize,
        peak_extra_qubits: builder.peak_qubits as usize - input_qubits,
        final_active_qubits,
        first_failure,
        clean,
    }
}

/// Exact operation-surface and dirty-lane census for the five blocked division
/// classes. Phase duplication yields the requested 20 production sites.
#[doc(hidden)]
pub fn q944_catalytic_blocked_operation_census() -> Q944CatalyticBlockedCensusReport {
    const ROWS: [usize; 5] = [374, 375, 376, 379, 380];
    let mut streams = Vec::new();
    for row in ROWS {
        streams.push(q944_catalytic_blocked_stream(row, false));
        streams.push(q944_catalytic_blocked_stream(row, true));
    }
    let mut sites = Vec::new();
    for (stream_index, stream) in streams.iter().enumerate() {
        for phase in ["ec3.inv_fwd", "ec3.alt.cancel"] {
            sites.push(Q944CatalyticBlockedSiteReport {
                phase,
                direction: if stream.inverse { "reverse" } else { "forward" },
                row: stream.row,
                stream_index,
                clean: stream.clean,
            });
        }
    }
    let clean_streams = streams.iter().filter(|stream| stream.clean).count();
    let clean_sites = sites.iter().filter(|site| site.clean).count();
    let first_failure = streams.iter().find_map(|stream| stream.first_failure.clone());
    let exact_clean = clean_streams == streams.len() && clean_sites == sites.len();
    Q944CatalyticBlockedCensusReport {
        rows_checked: ROWS.len(),
        streams_checked: streams.len(),
        sites_checked: sites.len(),
        clean_streams,
        blocked_streams: streams.len() - clean_streams,
        clean_sites,
        blocked_sites: sites.len() - clean_sites,
        source_operations: streams.iter().map(|stream| stream.source_operations).sum(),
        classified_operations: streams
            .iter()
            .map(|stream| stream.classified_operations)
            .sum(),
        unsupported_operations: streams
            .iter()
            .map(|stream| stream.unsupported_operations)
            .sum(),
        predicate_support_target_checks: streams
            .iter()
            .map(|stream| stream.predicate_support_target_checks)
            .sum(),
        predicate_support_target_conflicts: streams
            .iter()
            .map(|stream| stream.predicate_support_target_conflicts)
            .sum(),
        disjoint_pair_checks: streams
            .iter()
            .map(|stream| stream.disjoint_pair_checks)
            .sum(),
        disjoint_pair_misses: streams
            .iter()
            .map(|stream| stream.disjoint_pair_misses)
            .sum(),
        projected_operations: streams
            .iter()
            .map(|stream| stream.projected_operations)
            .sum(),
        projected_toffoli_class: streams
            .iter()
            .map(|stream| stream.projected_toffoli_class)
            .sum(),
        first_failure,
        streams,
        sites,
        exact_clean,
    }
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944QuotientDependencyFailure {
    pub row: usize,
    pub inverse: bool,
    pub operation_index: usize,
    pub phase: String,
    pub operation: Op,
    pub reason: &'static str,
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944QuotientDependencyStreamReport {
    pub row: usize,
    pub inverse: bool,
    pub widths: [usize; 5],
    pub baseline_operations: usize,
    pub baseline_toffoli_class: usize,
    pub baseline_input_qubits: usize,
    pub baseline_peak_qubits: usize,
    pub candidate_operations: usize,
    pub candidate_toffoli_class: usize,
    pub candidate_input_qubits: usize,
    pub candidate_peak_qubits: usize,
    pub candidate_peak_extra_qubits: usize,
    pub candidate_final_active_qubits: usize,
    pub candidate_body_start: usize,
    pub candidate_body_end: usize,
    pub candidate_body_q24_controls: usize,
    pub candidate_body_q24_targets: usize,
    pub candidate_body_predicate_support_targets: usize,
    pub candidate_body_hmr: usize,
    pub candidate_body_resets: usize,
    pub candidate_body_phase_sensitive: usize,
    pub arithmetic_operations: usize,
    pub partial_demux_operations: usize,
    pub crossed_operations: usize,
    pub crossed_hmr: usize,
    pub crossed_resets: usize,
    pub crossed_phase_sensitive: usize,
    pub crossed_unexpected_operations: usize,
    pub row374_dirty_compare_operations: usize,
    pub dirty_lenders_available: usize,
    pub dirty_lenders_required: usize,
    pub retained_gate_arithmetic_toffoli: usize,
    pub distributed_arithmetic_toffoli: usize,
    pub first_failure: Option<Q944QuotientDependencyFailure>,
    pub clean: bool,
}

#[derive(Clone, Debug, Eq, PartialEq)]
pub struct Q944QuotientDependencyCensusReport {
    pub rows_checked: usize,
    pub streams_checked: usize,
    pub sites_checked: usize,
    pub clean_streams: usize,
    pub blocked_streams: usize,
    pub clean_sites: usize,
    pub blocked_sites: usize,
    pub baseline_operations: usize,
    pub candidate_operations: usize,
    pub baseline_toffoli_class: usize,
    pub candidate_toffoli_class: usize,
    pub body_q24_target_conflicts: usize,
    pub crossed_noncommuting_operations: usize,
    pub dirty_lender_misses: usize,
    pub first_failure: Option<Q944QuotientDependencyFailure>,
    pub streams: Vec<Q944QuotientDependencyStreamReport>,
    pub exact_clean: bool,
}

fn q944_operation_phases(builder: &B) -> Vec<&'static str> {
    let mut phases = Vec::with_capacity(builder.ops.len());
    let mut current = "trailmix";
    let mut transition = 0usize;
    for index in 0..builder.ops.len() {
        while transition < builder.phase_transitions.len()
            && builder.phase_transitions[transition].0 <= index
        {
            current = builder.phase_transitions[transition].1;
            transition += 1;
        }
        phases.push(current);
    }
    phases
}

fn q944_phase_sensitive(op: &Op) -> bool {
    matches!(
        op.kind,
        OperationType::Neg | OperationType::Z | OperationType::CZ | OperationType::CCZ
    )
}

#[allow(clippy::too_many_arguments)]
fn q944_quotient_witness_candidate_stream(
    row: usize,
    inverse: bool,
) -> Q944QuotientDependencyStreamReport {
    use crate::point_add::trailmix_port::inversion::q944_quotient_witness::{
        q944_dirty_arithmetic_toffoli, q944_distributed_arithmetic_toffoli,
    };
    use crate::point_add::trailmix_port::inversion::q949_robust_envelope::
        q949_robust_pair_symmetric_widths;
    use crate::point_add::trailmix_port::inversion::shrunken_pz_schedule::shift_bounds;

    assert!([374, 375, 376, 379, 380].contains(&row));
    assert!(lowq_q945_local_hosts_enabled());
    assert!(lowq_q945_dirty_parity_arithmetic_enabled());
    assert!(lowq_q949_affine_counter_enabled());
    assert!(!lowq_q954_srot_counter7_enabled());

    fn rb(bound: usize) -> usize {
        if bound == 0 {
            1
        } else {
            64 - (bound as u64).leading_zeros() as usize
        }
    }

    let baseline = q944_catalytic_blocked_stream(row, inverse);
    let widths = q949_robust_pair_symmetric_widths(row);
    assert_eq!(widths[4], Q944_QUOTIENT_WIDTH);
    let [lo_a, lo_b, _, _, _] = trailmix_register_los_step(row);
    let (shift_bound, _) = shift_bounds(row);
    let mut circ = Circuit::new();
    let a = circ.alloc_qreg_bits("q944.qw.census.a", widths[0]);
    let b = circ.alloc_qreg_bits("q944.qw.census.b", widths[1]);
    let ca = circ.alloc_qreg_bits("q944.qw.census.ca", widths[2]);
    let cb = circ.alloc_qreg_bits("q944.qw.census.cb", widths[3]);
    let q = circ.alloc_qreg_bits("q944.qw.census.q", widths[4]);
    let counter = circ.alloc_qreg_bits("q944.qw.census.counter", trailmix_counter_width());
    let parity = circ.alloc_qreg("q944.qw.census.parity");
    let s_rot = circ.alloc_qreg_bits("q944.qw.census.srot", trailmix_srot_width());
    assert_eq!(counter.len(), 1);
    assert_eq!(s_rot.len(), 5);
    let off = &counter[0];
    let active = &q[Q944_QUOTIENT_SENTINEL];
    let extra_lenders: Vec<&QReg> = ca.iter().chain(cb.iter()).collect();
    let boundary_candidates: Vec<&QReg> = a
        .iter()
        .chain(b.iter())
        .chain(ca.iter())
        .chain(cb.iter())
        .chain(q.iter())
        .chain(counter.iter())
        .chain(s_rot.iter())
        .chain(std::iter::once(&parity))
        .chain(std::iter::once(off))
        .collect();
    let reverse_relational = inverse
        && row == BORROWED_ROW_380
        && lowq_reverse_ca255_relational_loan_enabled();
    let transcript_loans = q945_local_hclz_loans(
        row,
        inverse,
        BorrowedTranscriptSubstep::Division,
        &a,
        &b,
        &ca,
        &cb,
        &q,
        &counter,
        off,
    )
    .unwrap_or_else(|| {
        if reverse_relational {
            BorrowedTranscriptLoans::shared(borrowed_transcript_loan(
                row,
                inverse,
                BorrowedTranscriptSubstep::Division,
                &a,
                &ca,
                &cb,
                &counter,
                Some(active),
            ))
        } else {
            BorrowedTranscriptLoans::shared(borrowed_transcript_loan(
                row,
                inverse,
                BorrowedTranscriptSubstep::Division,
                &a,
                &ca,
                &cb,
                &counter,
                None,
            ))
        }
    });
    let q945_carry = q945_narrow_carry(
        row,
        Q945Substep::Division,
        &a,
        &b,
        &ca,
        &cb,
        &q,
        off,
        &parity,
    );
    let input_qubits = circ.b.active_qubits as usize;
    let s_refs: Vec<&QReg> = s_rot.iter().collect();
    if inverse {
        q944_reverse_park_sentinel(&mut circ, &q, &s_refs);
    }
    let mut body_start = 0usize;
    let mut body_end = 0usize;
    gate_hold_counter_zero(
        &mut circ,
        &ca,
        &cb,
        &counter,
        &parity,
        &s_rot,
        active,
        &boundary_candidates,
        |circ, gate| {
            assert!(std::ptr::eq(gate, active));
            body_start = circ.b.ops.len();
            with_arithmetic_srot_view(&s_rot, &counter, |s_rot_view| {
                if inverse {
                    division_substep_windowed_inv_mode(
                        circ,
                        &a,
                        &b,
                        &q,
                        s_rot_view,
                        off,
                        gate,
                        &extra_lenders,
                        lo_a,
                        lo_b,
                        rb(shift_bound),
                        q954_ctz_width(row),
                        transcript_loans,
                        q945_carry,
                        Q944DivisionQuotientMode::QuotientWitness,
                    );
                } else {
                    division_substep_windowed_mode(
                        circ,
                        &a,
                        &b,
                        &q,
                        s_rot_view,
                        off,
                        gate,
                        &extra_lenders,
                        lo_a,
                        lo_b,
                        rb(shift_bound),
                        q954_ctz_width(row),
                        transcript_loans,
                        q945_carry,
                        Q944DivisionQuotientMode::QuotientWitness,
                    );
                }
            });
            body_end = circ.b.ops.len();
        },
    );
    if !inverse {
        q944_commit_parked_sentinel(&mut circ, &q, &s_refs);
    }
    circ.flush_pending_frees();
    let final_active_qubits = circ.b.active_qubits as usize;
    assert_eq!(final_active_qubits, input_qubits);

    let active_id = QubitId(u64::from(active.id()));
    let predicate_support: Vec<QubitId> = ca
        .iter()
        .chain(cb.iter())
        .chain(counter.iter())
        .map(|lane| QubitId(u64::from(lane.id())))
        .collect();
    let builder = circ.into_builder();
    let phases = q944_operation_phases(&builder);
    let mut body_q24_controls = 0usize;
    let mut body_q24_targets = 0usize;
    let mut body_predicate_support_targets = 0usize;
    let mut body_hmr = 0usize;
    let mut body_resets = 0usize;
    let mut body_phase_sensitive = 0usize;
    let mut first_failure = None;
    for index in body_start..body_end {
        let op = &builder.ops[index];
        body_q24_controls += usize::from(
            op.q_control1 == active_id || op.q_control2 == active_id,
        );
        if op.q_target == active_id {
            body_q24_targets += 1;
            if first_failure.is_none() {
                first_failure = Some(Q944QuotientDependencyFailure {
                    row,
                    inverse,
                    operation_index: index,
                    phase: phases[index].to_owned(),
                    operation: *op,
                    reason: "quotient-sentinel-targeted-inside-hosted-body",
                });
            }
        }
        body_predicate_support_targets +=
            usize::from(predicate_support.contains(&op.q_target));
        body_hmr += usize::from(op.kind == OperationType::Hmr);
        body_resets += usize::from(op.kind == OperationType::R);
        body_phase_sensitive += usize::from(q944_phase_sensitive(op));
    }

    // Match only the independently proved dirty-parity arithmetic section.
    // Hybrid-CLZ helpers contain unrelated nested p.add/p.sub sections and
    // would otherwise make the dependency interval span the whole prelude.
    let arithmetic_label = if inverse {
        "/p.add/q944.dirty-carry-add"
    } else {
        "/p.sub/q944.dirty-carry-sub"
    };
    let arithmetic_indices: Vec<usize> = phases
        .iter()
        .enumerate()
        .filter_map(|(index, phase)| phase.contains(arithmetic_label).then_some(index))
        .collect();
    let demux_indices: Vec<usize> = phases
        .iter()
        .enumerate()
        .filter_map(|(index, phase)| {
            phase
                .contains("/q944.qw.partial-demux")
                .then_some(index)
        })
        .collect();
    assert!(!arithmetic_indices.is_empty());
    assert!(!demux_indices.is_empty());
    let arithmetic_first = arithmetic_indices[0];
    let arithmetic_last = *arithmetic_indices.last().unwrap();
    let demux_first = demux_indices[0];
    let demux_last = *demux_indices.last().unwrap();
    let order_clean = if inverse {
        arithmetic_last < demux_first
    } else {
        demux_last < arithmetic_first
    };
    let crossed_start = arithmetic_first.min(demux_first);
    let crossed_end = arithmetic_last.max(demux_last) + 1;
    let mut crossed_hmr = 0usize;
    let mut crossed_resets = 0usize;
    let mut crossed_phase_sensitive = 0usize;
    let mut crossed_unexpected_operations = 0usize;
    for index in crossed_start..crossed_end {
        let op = &builder.ops[index];
        crossed_hmr += usize::from(op.kind == OperationType::Hmr);
        crossed_resets += usize::from(op.kind == OperationType::R);
        crossed_phase_sensitive += usize::from(q944_phase_sensitive(op));
        if first_failure.is_none()
            && matches!(op.kind, OperationType::Hmr | OperationType::R)
        {
            first_failure = Some(Q944QuotientDependencyFailure {
                row,
                inverse,
                operation_index: index,
                phase: phases[index].to_owned(),
                operation: *op,
                reason: "measurement-or-reset-crossed-by-quotient-reorder",
            });
        }
        if first_failure.is_none() && q944_phase_sensitive(op) {
            first_failure = Some(Q944QuotientDependencyFailure {
                row,
                inverse,
                operation_index: index,
                phase: phases[index].to_owned(),
                operation: *op,
                reason: "phase-sensitive-operation-crossed-by-quotient-reorder",
            });
        }
        let expected = phases[index].contains(arithmetic_label)
            || phases[index].contains("/q944.qw.partial-demux");
        if !expected {
            crossed_unexpected_operations += 1;
            if first_failure.is_none() {
                first_failure = Some(Q944QuotientDependencyFailure {
                    row,
                    inverse,
                    operation_index: index,
                    phase: phases[index].to_owned(),
                    operation: *op,
                    reason: "noncommuting-operation-between-demux-and-arithmetic",
                });
            }
        }
    }
    if !order_clean && first_failure.is_none() {
        first_failure = Some(Q944QuotientDependencyFailure {
            row,
            inverse,
            operation_index: crossed_start,
            phase: phases[crossed_start].to_owned(),
            operation: builder.ops[crossed_start],
            reason: "quotient-handoff-order-mismatch",
        });
    }
    let row374_dirty_compare_operations = phases
        .iter()
        .filter(|phase| phase.contains("q944.dirty-carry-strict-compare"))
        .count();
    let row374_compare_clean = if row == 374 {
        row374_dirty_compare_operations > 0
    } else {
        row374_dirty_compare_operations == 0
    };
    if !row374_compare_clean && first_failure.is_none() {
        first_failure = Some(Q944QuotientDependencyFailure {
            row,
            inverse,
            operation_index: body_start,
            phase: phases[body_start].to_owned(),
            operation: builder.ops[body_start],
            reason: "row374-q24-carry-replacement-mismatch",
        });
    }
    let candidate_peak_qubits = builder.peak_qubits as usize;
    let peak_clean = candidate_peak_qubits + 1 == baseline.peak_qubits;
    if !peak_clean && first_failure.is_none() {
        first_failure = Some(Q944QuotientDependencyFailure {
            row,
            inverse,
            operation_index: builder.peak_ops_idx,
            phase: builder.peak_phase.to_owned(),
            operation: builder.ops[builder.peak_ops_idx.min(builder.ops.len() - 1)],
            reason: "candidate-did-not-remove-exactly-one-peak-live-qubit",
        });
    }
    let candidate_toffoli_class = builder.counted_kind_ops[OperationType::CCX as usize]
        + builder.counted_kind_ops[OperationType::CCZ as usize];
    let dirty_lenders_available = a.len() + b.len() + ca.len() + cb.len();
    let dirty_lenders_required = Q944_SHIFT_WIDTH - 1;
    let lender_clean = dirty_lenders_available >= dirty_lenders_required;
    if !lender_clean && first_failure.is_none() {
        first_failure = Some(Q944QuotientDependencyFailure {
            row,
            inverse,
            operation_index: body_start,
            phase: phases[body_start].to_owned(),
            operation: builder.ops[body_start],
            reason: "insufficient-disjoint-dirty-lenders-for-partial-demux",
        });
    }
    let clean = first_failure.is_none()
        && body_q24_targets == 0
        && order_clean
        && crossed_hmr == 0
        && crossed_resets == 0
        && crossed_phase_sensitive == 0
        && crossed_unexpected_operations == 0
        && row374_compare_clean
        && peak_clean
        && lender_clean;
    Q944QuotientDependencyStreamReport {
        row,
        inverse,
        widths,
        baseline_operations: baseline.source_operations,
        baseline_toffoli_class: baseline.source_toffoli_class,
        baseline_input_qubits: baseline.input_qubits,
        baseline_peak_qubits: baseline.peak_qubits,
        candidate_operations: builder.ops.len(),
        candidate_toffoli_class,
        candidate_input_qubits: input_qubits,
        candidate_peak_qubits,
        candidate_peak_extra_qubits: candidate_peak_qubits - input_qubits,
        candidate_final_active_qubits: final_active_qubits,
        candidate_body_start: body_start,
        candidate_body_end: body_end,
        candidate_body_q24_controls: body_q24_controls,
        candidate_body_q24_targets: body_q24_targets,
        candidate_body_predicate_support_targets: body_predicate_support_targets,
        candidate_body_hmr: body_hmr,
        candidate_body_resets: body_resets,
        candidate_body_phase_sensitive: body_phase_sensitive,
        arithmetic_operations: arithmetic_indices.len(),
        partial_demux_operations: demux_indices.len(),
        crossed_operations: crossed_end - crossed_start,
        crossed_hmr,
        crossed_resets,
        crossed_phase_sensitive,
        crossed_unexpected_operations,
        row374_dirty_compare_operations,
        dirty_lenders_available,
        dirty_lenders_required,
        retained_gate_arithmetic_toffoli: q944_dirty_arithmetic_toffoli(widths[0]),
        distributed_arithmetic_toffoli: q944_distributed_arithmetic_toffoli(widths[0]),
        first_failure,
        clean,
    }
}

/// Exact source-level dependency trace for the five blocked division rows in
/// both directions. The two challenge phases duplicate these ten streams into
/// the requested 20 structural sites.
#[doc(hidden)]
pub fn q944_quotient_witness_dependency_census() -> Q944QuotientDependencyCensusReport {
    const ROWS: [usize; 5] = [374, 375, 376, 379, 380];
    let mut streams = Vec::new();
    for row in ROWS {
        streams.push(q944_quotient_witness_candidate_stream(row, false));
        streams.push(q944_quotient_witness_candidate_stream(row, true));
    }
    let clean_streams = streams.iter().filter(|stream| stream.clean).count();
    let clean_sites = 2 * clean_streams;
    let first_failure = streams.iter().find_map(|stream| stream.first_failure.clone());
    let exact_clean = clean_streams == streams.len();
    Q944QuotientDependencyCensusReport {
        rows_checked: ROWS.len(),
        streams_checked: streams.len(),
        sites_checked: 2 * streams.len(),
        clean_streams,
        blocked_streams: streams.len() - clean_streams,
        clean_sites,
        blocked_sites: 2 * streams.len() - clean_sites,
        baseline_operations: streams.iter().map(|stream| stream.baseline_operations).sum(),
        candidate_operations: streams.iter().map(|stream| stream.candidate_operations).sum(),
        baseline_toffoli_class: streams
            .iter()
            .map(|stream| stream.baseline_toffoli_class)
            .sum(),
        candidate_toffoli_class: streams
            .iter()
            .map(|stream| stream.candidate_toffoli_class)
            .sum(),
        body_q24_target_conflicts: streams
            .iter()
            .map(|stream| stream.candidate_body_q24_targets)
            .sum(),
        crossed_noncommuting_operations: streams
            .iter()
            .map(|stream| {
                stream.crossed_hmr
                    + stream.crossed_resets
                    + stream.crossed_phase_sensitive
                    + stream.crossed_unexpected_operations
            })
            .sum(),
        dirty_lender_misses: streams
            .iter()
            .filter(|stream| stream.dirty_lenders_available < stream.dirty_lenders_required)
            .count(),
        first_failure,
        streams,
        exact_clean,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q954SrotCounter7Report {
    pub high_lane_differential_cases_checked: usize,
    pub body_forward_cases_checked: usize,
    pub body_reverse_cases_checked: usize,
    pub body_roundtrip_cases_checked: usize,
    pub late_inactive_cases_checked: usize,
    pub passenger_cases_checked: usize,
    pub passenger_release_intervals_checked: usize,
    pub srot_qubits_saved: usize,
    pub passenger_qubits_saved: usize,
    pub max_helper_toffoli_increase: usize,
}

/// Differentially check the borrowed high shift lane against a five-owned-lane
/// reference, including production division/multiply bodies and the late
/// inactive branch where counter[7] is one. Also exercise all canonical
/// passenger-top release intervals used by the Q954 route.
#[doc(hidden)]
pub fn q954_srot_counter7_roundtrip_check() -> Q954SrotCounter7Report {
    use crate::circuit::{OperationType, QubitId};
    use crate::point_add::B;
    use crate::sim::Simulator;
    use sha3::{
        digest::{ExtendableOutput, Update},
        Shake128,
    };

    assert!(lowq_q954_srot_counter7_enabled());
    let certificate = q954_srot_counter7_schedule_certificate();
    assert_eq!(certificate.first_terminal_capable_row, 371);
    assert_eq!(certificate.last_ctz_bit4_row, 477);
    assert_eq!(certificate.last_raw_bit4_barrel_row, 495);
    assert_eq!(certificate.max_pre_body_counter, 124);
    assert_eq!(certificate.max_final_counter, 159);

    struct Harness {
        builder: B,
        registers: Vec<Vec<u32>>,
        external: Vec<u32>,
    }

    #[derive(Debug, Eq, PartialEq)]
    struct Snapshot {
        registers: Vec<u64>,
        phase: u64,
        internal_clean: bool,
    }

    fn ids(reg: &[QReg]) -> Vec<u32> {
        reg.iter().map(QReg::id).collect()
    }

    fn external_ids(registers: &[Vec<u32>]) -> Vec<u32> {
        let mut out = Vec::new();
        for &id in registers.iter().flatten() {
            if !out.contains(&id) {
                out.push(id);
            }
        }
        out
    }

    fn simulate(harness: &Harness, values: &[u64]) -> Snapshot {
        assert_eq!(harness.registers.len(), values.len());
        let mut seed = Shake128::default();
        seed.update(b"q954-srot-counter7-differential");
        let mut xof = seed.finalize_xof();
        let mut sim = Simulator::new(
            harness.builder.next_qubit as usize,
            harness.builder.next_bit as usize,
            &mut xof,
        );
        for (register, &value) in harness.registers.iter().zip(values) {
            assert!(register.len() <= 64);
            for (bit, &id) in register.iter().enumerate() {
                if (value >> bit) & 1 == 1 {
                    *sim.qubit_mut(QubitId(u64::from(id))) |= 1;
                }
            }
        }
        sim.apply_iter(harness.builder.ops.iter());
        let registers = harness
            .registers
            .iter()
            .map(|register| {
                register.iter().enumerate().fold(0u64, |value, (bit, &id)| {
                    value | ((sim.qubit(QubitId(u64::from(id))) & 1) << bit)
                })
            })
            .collect();
        let internal_clean = (0..harness.builder.next_qubit).all(|id| {
            harness.external.contains(&id)
                || sim.qubit(QubitId(u64::from(id))) & 1 == 0
        });
        Snapshot {
            registers,
            phase: sim.phase & 1,
            internal_clean,
        }
    }

    fn toffoli(builder: &B) -> usize {
        builder
            .ops
            .iter()
            .filter(|op| matches!(op.kind, OperationType::CCX | OperationType::CCZ))
            .count()
    }

    // mode: 0=forward, 1=reverse, 2=forward+reverse.
    fn build_body(split: bool, multiply: bool, mode: u8) -> Harness {
        let mut c = Circuit::new();
        let a = c.alloc_qreg_bits("q954-body.a", 20);
        let b = c.alloc_qreg_bits("q954-body.b", 20);
        let q = c.alloc_qreg_bits("q954-body.q", 17);
        let owned = c.alloc_qreg_bits("q954-body.srot", if split { 4 } else { 5 });
        let counter = c.alloc_qreg_bits("q954-body.counter", 8);
        let active = c.alloc_qreg("q954-body.active");
        let lender_regs = c.alloc_qreg_bits("q954-body.lenders", 20);
        let lenders: Vec<&QReg> = lender_regs.iter().collect();
        let s_rot: Vec<&QReg> = if split {
            vec![
                &owned[0],
                &owned[1],
                &owned[2],
                &owned[3],
                &counter[7],
            ]
        } else {
            owned.iter().collect()
        };
        let off = &counter[0];
        let emit = |c: &mut Circuit, inverse: bool| {
            if multiply {
                if inverse {
                    multiply_substep_windowed_inv(
                        c, &a, &b, &q, &s_rot, off, &active, &lenders, 0, 0, 5, 5,
                        BorrowedTranscriptLoans::none(),
                        None,
                    );
                } else {
                    multiply_substep_windowed(
                        c, &a, &b, &q, &s_rot, off, &active, &lenders, 0, 0, 5, 5,
                        BorrowedTranscriptLoans::none(),
                        None,
                    );
                }
            } else if inverse {
                division_substep_windowed_inv(
                    c, &a, &b, &q, &s_rot, off, &active, &lenders, 0, 0, 5, 5,
                    BorrowedTranscriptLoans::none(),
                    None,
                );
            } else {
                division_substep_windowed(
                    c, &a, &b, &q, &s_rot, off, &active, &lenders, 0, 0, 5, 5,
                    BorrowedTranscriptLoans::none(),
                    None,
                );
            }
        };
        match mode {
            0 => emit(&mut c, false),
            1 => emit(&mut c, true),
            2 => {
                emit(&mut c, false);
                emit(&mut c, true);
            }
            _ => unreachable!(),
        }

        let mut s_ids = ids(&owned);
        if split {
            s_ids.push(counter[7].id());
        }
        let registers = vec![
            ids(&a),
            ids(&b),
            ids(&q),
            s_ids,
            ids(&counter),
            vec![active.id()],
            ids(&lender_regs),
        ];
        let external = external_ids(&registers);
        Harness {
            builder: c.into_builder(),
            registers,
            external,
        }
    }

    fn build_high_carry(split: bool, mode: u8) -> Harness {
        let mut c = Circuit::new();
        let owned = c.alloc_qreg_bits("q954-carry.srot", if split { 4 } else { 5 });
        let counter = c.alloc_qreg_bits("q954-carry.counter", 8);
        let active = c.alloc_qreg("q954-carry.active");
        let lenders = c.alloc_qreg_bits("q954-carry.lenders", 8);
        let candidates: Vec<&QReg> = lenders
            .iter()
            .chain(owned.iter())
            .chain(counter.iter())
            .chain(std::iter::once(&active))
            .collect();
        let s_rot: Vec<&QReg> = if split {
            vec![
                &owned[0],
                &owned[1],
                &owned[2],
                &owned[3],
                &counter[7],
            ]
        } else {
            owned.iter().collect()
        };
        let off = &counter[0];
        match mode {
            0 => ctrl_inc_by_off(&mut c, &active, off, &s_rot, &candidates),
            1 => ctrl_dec_by_off(&mut c, &active, off, &s_rot, &candidates),
            2 => {
                ctrl_inc_by_off(&mut c, &active, off, &s_rot, &candidates);
                ctrl_dec_by_off(&mut c, &active, off, &s_rot, &candidates);
            }
            _ => unreachable!(),
        }
        let mut s_ids = ids(&owned);
        if split {
            s_ids.push(counter[7].id());
        }
        let registers = vec![s_ids, ids(&counter), vec![active.id()], ids(&lenders)];
        let external = external_ids(&registers);
        Harness {
            builder: c.into_builder(),
            registers,
            external,
        }
    }

    fn build_late_inactive(roundtrip: bool) -> Harness {
        let mut c = Circuit::new();
        let owned = c.alloc_qreg_bits("q954-late.srot", 4);
        let counter = c.alloc_qreg_bits("q954-late.counter", 8);
        let parity = c.alloc_qreg("q954-late.parity");
        let gate = c.alloc_qreg("q954-late.gate");
        let x = c.alloc_qreg_bits("q954-late.x", 2);
        let y = c.alloc_qreg_bits("q954-late.y", 2);
        let a = c.alloc_qreg_bits("q954-late.a", 20);
        let b = c.alloc_qreg_bits("q954-late.b", 20);
        let q = c.alloc_qreg_bits("q954-late.q", 15);
        let lenders = c.alloc_qreg_bits("q954-late.lenders", 20);
        let candidates: Vec<&QReg> = owned
            .iter()
            .chain(counter.iter())
            .chain(std::iter::once(&parity))
            .chain(std::iter::once(&gate))
            .chain(x.iter())
            .chain(y.iter())
            .chain(a.iter())
            .chain(b.iter())
            .chain(q.iter())
            .chain(lenders.iter())
            .collect();
        let lender_refs: Vec<&QReg> = lenders.iter().collect();
        let emit = |c: &mut Circuit, inverse: bool| {
            gate_hold_counter_zero(
                c,
                &x,
                &y,
                &counter,
                &parity,
                &owned,
                &gate,
                &candidates,
                |c, active| {
                    with_arithmetic_srot_view(&owned, &counter, |s_rot| {
                        if inverse {
                            multiply_substep_windowed_inv(
                                c,
                                &a,
                                &b,
                                &q,
                                s_rot,
                                &counter[0],
                                active,
                                &lender_refs,
                                0,
                                0,
                                4,
                                4,
                                BorrowedTranscriptLoans::none(),
                                None,
                            );
                        } else {
                            multiply_substep_windowed(
                                c,
                                &a,
                                &b,
                                &q,
                                s_rot,
                                &counter[0],
                                active,
                                &lender_refs,
                                0,
                                0,
                                4,
                                4,
                                BorrowedTranscriptLoans::none(),
                                None,
                            );
                        }
                    });
                },
            );
        };
        emit(&mut c, false);
        if roundtrip {
            emit(&mut c, true);
        }
        let mut s_ids = ids(&owned);
        s_ids.push(counter[7].id());
        let registers = vec![
            s_ids,
            ids(&counter),
            vec![parity.id()],
            vec![gate.id()],
            ids(&x),
            ids(&y),
            ids(&a),
            ids(&b),
            ids(&q),
            ids(&lenders),
        ];
        let external = external_ids(&registers);
        Harness {
            builder: c.into_builder(),
            registers,
            external,
        }
    }

    let mut high_lane_differential_cases_checked = 0usize;
    let mut body_forward_cases_checked = 0usize;
    let mut body_reverse_cases_checked = 0usize;
    let mut body_roundtrip_cases_checked = 0usize;
    let mut max_helper_toffoli_increase = 0usize;

    for multiply in [false, true] {
        let pre = if multiply {
            [0, 1, 1 << 16, 0, 0, 1, 0]
        } else {
            [1 << 16, 1, 0, 0, 0, 1, 0]
        };
        let post = if multiply {
            [1 << 16, 1, 0, 0, 0, 1, 0]
        } else {
            [0, 1, 1 << 16, 0, 0, 1, 0]
        };
        for mode in 0..=2u8 {
            let canonical = build_body(false, multiply, mode);
            let split = build_body(true, multiply, mode);
            let input = if mode == 1 { &post } else { &pre };
            let expected = if mode == 0 { &post } else { &pre };
            let canonical_out = simulate(&canonical, input);
            let split_out = simulate(&split, input);
            assert_eq!(canonical_out.registers, expected);
            assert_eq!(split_out.registers, expected);
            assert_eq!(split_out.registers, canonical_out.registers);
            assert!(canonical_out.internal_clean && split_out.internal_clean);
            if mode == 2 {
                assert_eq!(canonical_out.phase, 0);
                assert_eq!(split_out.phase, 0);
            }
            let canonical_t = toffoli(&canonical.builder);
            let split_t = toffoli(&split.builder);
            assert_eq!(
                split.builder.peak_qubits + 1,
                canonical.builder.peak_qubits,
                "Q954 split body must remove exactly one physical shift lane"
            );
            max_helper_toffoli_increase =
                max_helper_toffoli_increase.max(split_t.saturating_sub(canonical_t));
            assert!(
                split_t <= canonical_t,
                "Q954 split body increased helper Toffoli count"
            );
            match mode {
                0 => body_forward_cases_checked += 1,
                1 => body_reverse_cases_checked += 1,
                2 => body_roundtrip_cases_checked += 1,
                _ => unreachable!(),
            }
        }
    }

    for mode in 0..=2u8 {
        let canonical = build_high_carry(false, mode);
        let split = build_high_carry(true, mode);
        let pre = [15, 1, 1, 0];
        let post_canonical = [16, 1, 1, 0];
        let post_split = [16, 129, 1, 0];
        let input_canonical = if mode == 1 { &post_canonical } else { &pre };
        let input_split = if mode == 1 { &post_split } else { &pre };
        let canonical_out = simulate(&canonical, input_canonical);
        let split_out = simulate(&split, input_split);
        let expected_canonical = if mode == 0 { &post_canonical } else { &pre };
        let expected_split = if mode == 0 { &post_split } else { &pre };
        assert_eq!(canonical_out.registers, expected_canonical);
        assert_eq!(split_out.registers, expected_split);
        assert_eq!(canonical_out.registers[0], split_out.registers[0]);
        assert_eq!(canonical_out.registers[1] & 0x7f, split_out.registers[1] & 0x7f);
        assert!(canonical_out.internal_clean && split_out.internal_clean);
        let canonical_t = toffoli(&canonical.builder);
        let split_t = toffoli(&split.builder);
        assert_eq!(
            split.builder.peak_qubits + 1,
            canonical.builder.peak_qubits,
            "Q954 split carry must remove exactly one physical shift lane"
        );
        max_helper_toffoli_increase =
            max_helper_toffoli_increase.max(split_t.saturating_sub(canonical_t));
        assert!(split_t <= canonical_t, "Q954 split carry increased Toffoli count");
        high_lane_differential_cases_checked += 1;
    }

    let late_values = [16, 128, 1, 0, 0, 1, 3, 1, 8, 0];
    let late_forward = build_late_inactive(false);
    let late_roundtrip = build_late_inactive(true);
    for (case, harness) in [&late_forward, &late_roundtrip].into_iter().enumerate() {
        let out = simulate(harness, &late_values);
        assert_eq!(out.registers, late_values);
        assert_eq!(out.registers[0], 16, "late counter[7] alias was not restored");
        assert_eq!(out.registers[1], 128, "late counter changed");
        assert!(out.internal_clean, "late inactive body retained an ancilla");
        if case == 1 {
            assert_eq!(out.phase, 0);
        }
    }

    // Canonical passenger lifetime proof: three production intervals (divide
    // forward, cancel forward, cancel reverse), each removing exactly one lane.
    let mut c = Circuit::new();
    let mut passenger = c.alloc_qreg_bits("q954-passenger", 257);
    let lower_ids = ids(&passenger[..64]);
    let all_lower_ids = ids(&passenger[..256]);
    let original_top_id = passenger[256].id();
    let witness = c.alloc_qreg("q954-passenger.top-witness");
    let live_before = c.b.active_qubits as usize;
    for interval in 0..3 {
        let context = match interval {
            0 => "proof divide-forward",
            1 => "proof cancel-forward",
            _ => "proof cancel-reverse",
        };
        c.cx(&passenger[256], &witness);
        let released = release_canonical_passenger_top(
            &mut c,
            &mut passenger,
            context,
        );
        assert_eq!(released.physical_id(), original_top_id);
        let workspace = c.alloc_qreg_bits("q954-passenger.workspace", 7);
        assert!(workspace.iter().all(|lane| lane.id() != original_top_id));
        assert_eq!(
            c.b.active_qubits as usize,
            live_before - 1 + workspace.len(),
            "Q954 passenger interval did not save exactly one lane"
        );
        for lane in workspace {
            c.zero_and_free(lane);
        }
        restore_canonical_passenger_top(&mut c, &mut passenger, released, context);
        assert_eq!(passenger[256].id(), original_top_id);
        assert_eq!(c.b.active_qubits as usize, live_before);
    }
    let final_top_id = passenger[256].id();
    let registers = vec![lower_ids, vec![final_top_id], vec![witness.id()]];
    let mut external = all_lower_ids;
    external.push(final_top_id);
    external.push(witness.id());
    let passenger_harness = Harness {
        builder: c.into_builder(),
        registers,
        external,
    };
    let mut passenger_cases_checked = 0usize;
    for value in [0, 1, 2, 3, u64::MAX, 0x0123_4567_89ab_cdef] {
        let out = simulate(&passenger_harness, &[value, 0, 0]);
        assert_eq!(out.registers, [value, 0, 0]);
        assert!(out.internal_clean);
        passenger_cases_checked += 1;
    }

    assert_eq!(max_helper_toffoli_increase, 0);
    Q954SrotCounter7Report {
        high_lane_differential_cases_checked,
        body_forward_cases_checked,
        body_reverse_cases_checked,
        body_roundtrip_cases_checked,
        late_inactive_cases_checked: 2,
        passenger_cases_checked,
        passenger_release_intervals_checked: 3,
        srot_qubits_saved: 1,
        passenger_qubits_saved: 1,
        max_helper_toffoli_increase,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct BorrowedTranscriptHelperReport {
    pub logical_transcript_lanes: usize,
    pub owned_transcript_lanes: usize,
    pub preterminal_lease_sites: usize,
    pub row_379_lease_sites: usize,
    pub row_380_lease_sites: usize,
    pub reverse_ca_relational_lease_enabled: bool,
    pub active_cases_checked: usize,
    pub inactive_cases_checked: usize,
    pub high_branch_cases_checked: usize,
    pub roundtrip_cases_checked: usize,
    pub phase_cleanup_cases_checked: usize,
    pub ancilla_cleanup_cases_checked: usize,
    pub borrowed_lane_restoration_cases_checked: usize,
    pub baseline_peak_qubits: usize,
    pub borrowed_peak_qubits: usize,
    pub single_reset_savings: usize,
    pub roundtrip_reset_savings: usize,
}

/// Differential gate-level check for a seven-bit CLZ transcript backed by six
/// owned lanes and one clean lender. The harness covers active and inactive
/// branches, exercises the distance-64 branch, checks a forward-forward
/// roundtrip, and compares every non-reset operation kind with the owned-only
/// implementation.
#[doc(hidden)]
pub fn borrowed_transcript_roundtrip_check() -> BorrowedTranscriptHelperReport {
    use crate::circuit::{OperationType, QubitId};
    use crate::point_add::B;
    use crate::sim::Simulator;
    use sha3::{digest::{ExtendableOutput, Update}, Shake128};

    assert!(lowq_borrowed_transcript_experiment_enabled());
    assert_borrowed_transcript_lender_certificate();

    struct Harness {
        builder: B,
        active: u32,
        out: u32,
        lender: u32,
        a: Vec<u32>,
        b: Vec<u32>,
        external: Vec<u32>,
    }

    #[derive(Clone, Copy)]
    struct Exercise {
        active_cases: usize,
        inactive_cases: usize,
        high_branch_cases: usize,
        phase_cases: usize,
        ancilla_cases: usize,
        lender_cases: usize,
    }

    fn ids(reg: &[QReg]) -> Vec<u32> {
        reg.iter().map(QReg::id).collect()
    }

    fn build(borrowed: bool, roundtrip: bool) -> Harness {
        let mut c = Circuit::new();
        let active = c.alloc_qreg("borrowed-transcript.active");
        let out = c.alloc_qreg("borrowed-transcript.out");
        let lender = c.alloc_qreg("borrowed-transcript.lender");
        let a = c.alloc_qreg_bits("borrowed-transcript.a", 72);
        let b = c.alloc_qreg_bits("borrowed-transcript.b", 72);
        let loan = borrowed.then_some(BorrowedTranscriptLoan {
            lane: &lender,
            kind: BorrowedTranscriptLoanKind::ProofHarness,
            row: BORROWED_ROW_380,
            inverse: false,
            substep: BorrowedTranscriptSubstep::Division,
            preparation: BorrowedTranscriptPreparation::AlreadyZero,
        });
        hybrid_bitlen_diff_parity(&mut c, &a, &b, 0, 0, &out, &active, loan);
        if roundtrip {
            hybrid_bitlen_diff_parity(&mut c, &a, &b, 0, 0, &out, &active, loan);
        }
        let a_ids = ids(&a);
        let b_ids = ids(&b);
        let external: Vec<u32> = [active.id(), out.id(), lender.id()]
            .into_iter()
            .chain(a_ids.iter().copied())
            .chain(b_ids.iter().copied())
            .collect();
        Harness {
            builder: c.into_builder(),
            active: active.id(),
            out: out.id(),
            lender: lender.id(),
            a: a_ids,
            b: b_ids,
            external,
        }
    }

    fn exercise(harness: &Harness, roundtrip: bool) -> Exercise {
        let mut seed = Shake128::default();
        let domain: &[u8] = if roundtrip {
            b"borrowed-transcript-roundtrip"
        } else {
            b"borrowed-transcript-forward"
        };
        seed.update(domain);
        let mut xof = seed.finalize_xof();
        let mut sim = Simulator::new(
            harness.builder.next_qubit as usize,
            harness.builder.next_bit as usize,
            &mut xof,
        );
        let mut expected_active = 0u64;
        let mut expected_out = 0u64;
        let mut expected_a = vec![0u64; harness.a.len()];
        let mut expected_b = vec![0u64; harness.b.len()];
        let mut active_cases = 0usize;
        let mut inactive_cases = 0usize;
        let mut high_branch_cases = 0usize;

        for shot in 0..64usize {
            let a_bit = if shot < 8 { shot } else { (13 * shot + 5) % 72 };
            let b_bit = if (8..16).contains(&shot) {
                shot - 8
            } else {
                (17 * shot + 9) % 72
            };
            let active = shot & 1 == 1;
            let out_before = shot & 2 == 2;
            let parity = (a_bit ^ b_bit) & 1 == 1;
            let out_after = if roundtrip {
                out_before
            } else {
                out_before ^ (active && parity)
            };
            if active {
                expected_active |= 1u64 << shot;
                active_cases += 1;
            } else {
                inactive_cases += 1;
            }
            if out_before {
                *sim.qubit_mut(QubitId(u64::from(harness.out))) |= 1u64 << shot;
            }
            if out_after {
                expected_out |= 1u64 << shot;
            }
            if active {
                *sim.qubit_mut(QubitId(u64::from(harness.active))) |= 1u64 << shot;
            }
            *sim.qubit_mut(QubitId(u64::from(harness.a[a_bit]))) |= 1u64 << shot;
            *sim.qubit_mut(QubitId(u64::from(harness.b[b_bit]))) |= 1u64 << shot;
            expected_a[a_bit] |= 1u64 << shot;
            expected_b[b_bit] |= 1u64 << shot;
            if a_bit < 8 || b_bit < 8 {
                high_branch_cases += 1;
            }
        }

        sim.apply_iter(harness.builder.ops.iter());
        assert_eq!(sim.qubit(QubitId(u64::from(harness.active))), expected_active);
        assert_eq!(sim.qubit(QubitId(u64::from(harness.out))), expected_out);
        assert_eq!(
            sim.qubit(QubitId(u64::from(harness.lender))),
            0,
            "borrowed transcript lane was not restored"
        );
        for (index, &id) in harness.a.iter().enumerate() {
            assert_eq!(sim.qubit(QubitId(u64::from(id))), expected_a[index]);
        }
        for (index, &id) in harness.b.iter().enumerate() {
            assert_eq!(sim.qubit(QubitId(u64::from(id))), expected_b[index]);
        }
        assert_eq!(sim.phase, 0, "borrowed transcript left phase garbage");
        for id in 0..harness.builder.next_qubit {
            if !harness.external.contains(&id) {
                assert_eq!(
                    sim.qubit(QubitId(u64::from(id))),
                    0,
                    "borrowed transcript left internal q{id} dirty"
                );
            }
        }
        Exercise {
            active_cases,
            inactive_cases,
            high_branch_cases,
            phase_cases: 64,
            ancilla_cases: 64,
            lender_cases: 64,
        }
    }

    let owned_forward = build(false, false);
    let borrowed_forward = build(true, false);
    let owned_roundtrip = build(false, true);
    let borrowed_roundtrip = build(true, true);
    let exercises = [
        exercise(&owned_forward, false),
        exercise(&borrowed_forward, false),
        exercise(&owned_roundtrip, true),
        exercise(&borrowed_roundtrip, true),
    ];

    for (owned, borrowed, expected_reset_savings) in [
        (&owned_forward.builder, &borrowed_forward.builder, 1usize),
        (&owned_roundtrip.builder, &borrowed_roundtrip.builder, 2usize),
    ] {
        assert_eq!(
            owned.peak_qubits,
            borrowed.peak_qubits + 1,
            "borrowed transcript lease did not save exactly one helper lane"
        );
        for kind in 0..owned.counted_kind_ops.len() {
            if kind == OperationType::R as usize {
                continue;
            }
            assert_eq!(
                owned.counted_kind_ops[kind], borrowed.counted_kind_ops[kind],
                "borrowed transcript lease changed operation kind {kind}"
            );
        }
        assert_eq!(
            owned.counted_kind_ops[OperationType::R as usize],
            borrowed.counted_kind_ops[OperationType::R as usize] + expected_reset_savings,
            "borrowed transcript reset savings drift"
        );
    }

    let phase_cleanup_cases_checked = exercises.iter().map(|e| e.phase_cases).sum();
    let ancilla_cleanup_cases_checked = exercises.iter().map(|e| e.ancilla_cases).sum();
    let borrowed_lane_restoration_cases_checked =
        exercises[1].lender_cases + exercises[3].lender_cases;
    assert!(exercises[1].high_branch_cases > 0);

    BorrowedTranscriptHelperReport {
        logical_transcript_lanes: BORROWED_TRANSCRIPT_LOGICAL_WIDTH,
        owned_transcript_lanes: BORROWED_TRANSCRIPT_LOGICAL_WIDTH - 1,
        preterminal_lease_sites: Q949_FIRST_TERMINAL_ROW * 2 * 2,
        row_379_lease_sites: 2,
        row_380_lease_sites: 1,
        reverse_ca_relational_lease_enabled: false,
        active_cases_checked: exercises[1].active_cases,
        inactive_cases_checked: exercises[1].inactive_cases,
        high_branch_cases_checked: exercises[1].high_branch_cases,
        roundtrip_cases_checked: 64,
        phase_cleanup_cases_checked,
        ancilla_cleanup_cases_checked,
        borrowed_lane_restoration_cases_checked,
        baseline_peak_qubits: owned_forward.builder.peak_qubits as usize,
        borrowed_peak_qubits: borrowed_forward.builder.peak_qubits as usize,
        single_reset_savings: 1,
        roundtrip_reset_savings: 2,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct ReverseCa255RelationalLoanReport {
    pub relation_states_checked: usize,
    pub active_cases_checked: usize,
    pub inactive_cases_checked: usize,
    pub roundtrip_cases_checked: usize,
    pub phase_cleanup_cases_checked: usize,
    pub ancilla_cleanup_cases_checked: usize,
    pub lender_restoration_cases_checked: usize,
    pub baseline_peak_qubits: usize,
    pub relational_peak_qubits: usize,
    pub single_x_overhead: usize,
    pub single_cx_overhead: usize,
    pub roundtrip_x_overhead: usize,
    pub roundtrip_cx_overhead: usize,
}

/// Exhaustive gate-level check of the two-state relation
/// `lender = NOT(active_and_ca_lt_cb)`. The live division predicate is the
/// relation control. X/CX normalization acquires a zero lane, the hybrid CLZ
/// body restores it, and the inverse normalization restores the relation.
#[doc(hidden)]
pub fn reverse_ca255_relational_loan_roundtrip_check() -> ReverseCa255RelationalLoanReport {
    use crate::circuit::{OperationType, QubitId};
    use crate::point_add::B;
    use crate::sim::Simulator;
    use sha3::{
        digest::{ExtendableOutput, Update},
        Shake128,
    };

    assert!(lowq_reverse_ca255_relational_loan_enabled());
    assert_borrowed_transcript_lender_certificate();

    struct Harness {
        builder: B,
        relation_control: u32,
        out: u32,
        lender: u32,
        a: Vec<u32>,
        b: Vec<u32>,
        external: Vec<u32>,
    }

    fn ids(reg: &[QReg]) -> Vec<u32> {
        reg.iter().map(QReg::id).collect()
    }

    fn build(relational: bool, roundtrip: bool) -> Harness {
        let mut c = Circuit::new();
        let relation_control = c.alloc_qreg("reverse-ca255.relation-control");
        let out = c.alloc_qreg("reverse-ca255.out");
        let lender = c.alloc_qreg("reverse-ca255.lender");
        let a = c.alloc_qreg_bits("reverse-ca255.a", 72);
        let b = c.alloc_qreg_bits("reverse-ca255.b", 72);
        let loan = relational.then_some(BorrowedTranscriptLoan {
            lane: &lender,
            kind: BorrowedTranscriptLoanKind::Row380ReverseCaHigh,
            row: BORROWED_ROW_380,
            inverse: true,
            substep: BorrowedTranscriptSubstep::Division,
            preparation: BorrowedTranscriptPreparation::ComplementOf(&relation_control),
        });
        hybrid_bitlen_diff_parity(
            &mut c,
            &a,
            &b,
            0,
            0,
            &out,
            &relation_control,
            loan,
        );
        if roundtrip {
            hybrid_bitlen_diff_parity(
                &mut c,
                &a,
                &b,
                0,
                0,
                &out,
                &relation_control,
                loan,
            );
        }
        let a_ids = ids(&a);
        let b_ids = ids(&b);
        let external: Vec<u32> = [relation_control.id(), out.id(), lender.id()]
            .into_iter()
            .chain(a_ids.iter().copied())
            .chain(b_ids.iter().copied())
            .collect();
        Harness {
            builder: c.into_builder(),
            relation_control: relation_control.id(),
            out: out.id(),
            lender: lender.id(),
            a: a_ids,
            b: b_ids,
            external,
        }
    }

    fn exercise(harness: &Harness, roundtrip: bool) {
        let mut seed = Shake128::default();
        let domain: &[u8] = if roundtrip {
            b"reverse-ca255-relational-roundtrip"
        } else {
            b"reverse-ca255-relational-forward"
        };
        seed.update(domain);
        let mut xof = seed.finalize_xof();
        let mut sim = Simulator::new(
            harness.builder.next_qubit as usize,
            harness.builder.next_bit as usize,
            &mut xof,
        );
        let mut expected_control = 0u64;
        let mut expected_out = 0u64;
        let mut expected_lender = 0u64;
        let mut expected_a = vec![0u64; harness.a.len()];
        let mut expected_b = vec![0u64; harness.b.len()];
        for shot in 0..64usize {
            let active = shot & 1 == 1;
            let out_before = shot & 2 == 2;
            let a_bit = (13 * shot + 5) % 72;
            let b_bit = (17 * shot + 9) % 72;
            let parity = (a_bit ^ b_bit) & 1 == 1;
            let out_after = if roundtrip {
                out_before
            } else {
                out_before ^ (active && parity)
            };
            if active {
                expected_control |= 1u64 << shot;
                *sim.qubit_mut(QubitId(u64::from(harness.relation_control))) |= 1u64 << shot;
            } else {
                expected_lender |= 1u64 << shot;
                *sim.qubit_mut(QubitId(u64::from(harness.lender))) |= 1u64 << shot;
            }
            if out_before {
                *sim.qubit_mut(QubitId(u64::from(harness.out))) |= 1u64 << shot;
            }
            if out_after {
                expected_out |= 1u64 << shot;
            }
            *sim.qubit_mut(QubitId(u64::from(harness.a[a_bit]))) |= 1u64 << shot;
            *sim.qubit_mut(QubitId(u64::from(harness.b[b_bit]))) |= 1u64 << shot;
            expected_a[a_bit] |= 1u64 << shot;
            expected_b[b_bit] |= 1u64 << shot;
        }

        sim.apply_iter(harness.builder.ops.iter());
        assert_eq!(
            sim.qubit(QubitId(u64::from(harness.relation_control))),
            expected_control
        );
        assert_eq!(sim.qubit(QubitId(u64::from(harness.out))), expected_out);
        assert_eq!(
            sim.qubit(QubitId(u64::from(harness.lender))),
            expected_lender,
            "reverse ca[255] relation was not restored"
        );
        for (index, &id) in harness.a.iter().enumerate() {
            assert_eq!(sim.qubit(QubitId(u64::from(id))), expected_a[index]);
        }
        for (index, &id) in harness.b.iter().enumerate() {
            assert_eq!(sim.qubit(QubitId(u64::from(id))), expected_b[index]);
        }
        assert_eq!(sim.phase, 0, "reverse ca[255] loan left phase garbage");
        for id in 0..harness.builder.next_qubit {
            if !harness.external.contains(&id) {
                assert_eq!(
                    sim.qubit(QubitId(u64::from(id))),
                    0,
                    "reverse ca[255] loan left internal q{id} dirty"
                );
            }
        }
    }

    let owned_forward = build(false, false);
    let relational_forward = build(true, false);
    let owned_roundtrip = build(false, true);
    let relational_roundtrip = build(true, true);
    exercise(&owned_forward, false);
    exercise(&relational_forward, false);
    exercise(&owned_roundtrip, true);
    exercise(&relational_roundtrip, true);

    let operation_delta = |kind: OperationType, owned: &B, relational: &B| {
        relational.counted_kind_ops[kind as usize] as isize
            - owned.counted_kind_ops[kind as usize] as isize
    };
    for (owned, relational, repetitions) in [
        (&owned_forward.builder, &relational_forward.builder, 1usize),
        (&owned_roundtrip.builder, &relational_roundtrip.builder, 2usize),
    ] {
        assert_eq!(owned.peak_qubits, relational.peak_qubits + 1);
        assert_eq!(operation_delta(OperationType::X, owned, relational), (2 * repetitions) as isize);
        assert_eq!(operation_delta(OperationType::CX, owned, relational), (2 * repetitions) as isize);
        assert_eq!(operation_delta(OperationType::R, owned, relational), -(repetitions as isize));
        for kind in 0..owned.counted_kind_ops.len() {
            if matches!(kind, x if x == OperationType::X as usize || x == OperationType::CX as usize || x == OperationType::R as usize) {
                continue;
            }
            assert_eq!(owned.counted_kind_ops[kind], relational.counted_kind_ops[kind]);
        }
    }

    ReverseCa255RelationalLoanReport {
        relation_states_checked: 2,
        active_cases_checked: 32,
        inactive_cases_checked: 32,
        roundtrip_cases_checked: 64,
        phase_cleanup_cases_checked: 2 * 64,
        ancilla_cleanup_cases_checked: 2 * 64,
        lender_restoration_cases_checked: 2 * 64,
        baseline_peak_qubits: owned_forward.builder.peak_qubits as usize,
        relational_peak_qubits: relational_forward.builder.peak_qubits as usize,
        single_x_overhead: 2,
        single_cx_overhead: 2,
        roundtrip_x_overhead: 4,
        roundtrip_cx_overhead: 4,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct PassengerTopLifetimeHelperReport {
    pub canonical_cases_checked: usize,
    pub canonical_zero_observations_checked: usize,
    pub noncanonical_witness_cases_checked: usize,
    pub release_intervals_checked: usize,
    pub forward_intervals_checked: usize,
    pub reverse_intervals_checked: usize,
    pub cancel_symmetric_pairs_checked: usize,
    pub physical_id_reacquisitions_checked: usize,
    pub reserved_id_nonreuse_checks: usize,
    pub passenger_release_reset_ops: usize,
    pub emitted_toffoli: usize,
    pub emitted_hmr: usize,
    pub phase_cleanup_cases_checked: usize,
    pub ancilla_cleanup_cases_checked: usize,
    pub initial_active_qubits: usize,
    pub final_active_qubits: usize,
}

/// Focused structural proof for the three production passenger intervals. The
/// canonical representation supplies a zero 257th lane; a witness observes that
/// precondition before every release, while a noncanonical control case proves
/// the witness is live. Each restore must reacquire the original physical ID,
/// and a probe allocation confirms the reserved ID cannot be reused meanwhile.
#[doc(hidden)]
pub fn passenger_top_lifetime_roundtrip_check() -> PassengerTopLifetimeHelperReport {
    use crate::circuit::{OperationType, QubitId};
    use crate::point_add::B;
    use crate::sim::Simulator;
    use sha3::{
        digest::{ExtendableOutput, Update},
        Shake128,
    };

    assert!(lowq_passenger_top_lifetime_experiment_enabled());
    assert!(!lowq_q954_srot_counter7_enabled());

    struct Harness {
        builder: B,
        registers: Vec<Vec<u32>>,
        external: Vec<u32>,
    }

    #[derive(Debug, Eq, PartialEq)]
    struct Snapshot {
        registers: Vec<u64>,
        phase: u64,
        internal_clean: bool,
    }

    fn ids(reg: &[QReg]) -> Vec<u32> {
        reg.iter().map(QReg::id).collect()
    }

    fn simulate(harness: &Harness, values: &[u64]) -> Snapshot {
        assert_eq!(harness.registers.len(), values.len());
        let mut seed = Shake128::default();
        seed.update(b"passenger-top-lifetime-proof");
        let mut xof = seed.finalize_xof();
        let mut sim = Simulator::new(
            harness.builder.next_qubit as usize,
            harness.builder.next_bit as usize,
            &mut xof,
        );
        for (register, &value) in harness.registers.iter().zip(values) {
            assert!(register.len() <= 64);
            for (bit, &id) in register.iter().enumerate() {
                if (value >> bit) & 1 == 1 {
                    *sim.qubit_mut(QubitId(u64::from(id))) |= 1;
                }
            }
        }
        sim.apply_iter(harness.builder.ops.iter());
        let registers = harness
            .registers
            .iter()
            .map(|register| {
                register.iter().enumerate().fold(0u64, |value, (bit, &id)| {
                    value | ((sim.qubit(QubitId(u64::from(id))) & 1) << bit)
                })
            })
            .collect();
        let internal_clean = (0..harness.builder.next_qubit).all(|id| {
            harness.external.contains(&id) || sim.qubit(QubitId(u64::from(id))) == 0
        });
        Snapshot {
            registers,
            phase: sim.phase,
            internal_clean,
        }
    }

    let intervals = [
        ("proof divide-forward", false),
        ("proof cancel-forward", false),
        ("proof cancel-reverse", true),
    ];
    let mut c = Circuit::new();
    let mut passenger = c.alloc_qreg_bits("passenger-top", 257);
    let all_passenger_ids = ids(&passenger);
    let lower_ids = ids(&passenger[..64]);
    let original_top_id = passenger[256].id();
    let witness = c.alloc_qreg("passenger-top.top-zero-witness");
    let initial_active_qubits = c.b.active_qubits as usize;
    let mut forward_intervals_checked = 0usize;
    let mut reverse_intervals_checked = 0usize;
    let mut physical_id_reacquisitions_checked = 0usize;
    let mut reserved_id_nonreuse_checks = 0usize;
    let mut passenger_release_reset_ops = 0usize;

    for (context, inverse) in intervals {
        c.cx(&passenger[256], &witness);
        let resets_before = c.b.counted_kind_ops[OperationType::R as usize];
        let released = release_canonical_passenger_top(&mut c, &mut passenger, context);
        passenger_release_reset_ops +=
            c.b.counted_kind_ops[OperationType::R as usize] - resets_before;
        assert_eq!(released.physical_id(), original_top_id);

        let probe = c.alloc_qreg("passenger-top.reservation-probe");
        assert_ne!(
            probe.id(),
            original_top_id,
            "reserved passenger ID was reused before restore"
        );
        reserved_id_nonreuse_checks += 1;
        c.zero_and_free(probe);

        restore_canonical_passenger_top(&mut c, &mut passenger, released, context);
        assert_eq!(passenger[256].id(), original_top_id);
        assert_eq!(c.b.active_qubits as usize, initial_active_qubits);
        physical_id_reacquisitions_checked += 1;
        if inverse {
            reverse_intervals_checked += 1;
        } else {
            forward_intervals_checked += 1;
        }
    }

    assert_eq!(forward_intervals_checked, 2);
    assert_eq!(reverse_intervals_checked, 1);
    assert_eq!(passenger_release_reset_ops, intervals.len());
    let final_active_qubits = c.b.active_qubits as usize;
    assert_eq!(final_active_qubits, initial_active_qubits);
    let final_top_id = passenger[256].id();
    let registers = vec![lower_ids, vec![final_top_id], vec![witness.id()]];
    let mut external = all_passenger_ids;
    external.push(witness.id());
    let harness = Harness {
        builder: c.into_builder(),
        registers,
        external,
    };
    let emitted_toffoli = harness.builder.counted_kind_ops[OperationType::CCX as usize]
        + harness.builder.counted_kind_ops[OperationType::CCZ as usize];
    let emitted_hmr = harness.builder.counted_kind_ops[OperationType::Hmr as usize];
    assert_eq!(emitted_toffoli, 0);
    assert_eq!(emitted_hmr, 0);

    let canonical_values = [0, 1, 2, 3, u64::MAX, 0x0123_4567_89ab_cdef];
    let mut phase_cleanup_cases_checked = 0usize;
    let mut ancilla_cleanup_cases_checked = 0usize;
    for value in canonical_values {
        let out = simulate(&harness, &[value, 0, 0]);
        assert_eq!(out.registers, [value, 0, 0]);
        assert_eq!(out.phase, 0);
        assert!(out.internal_clean);
        phase_cleanup_cases_checked += 1;
        ancilla_cleanup_cases_checked += 1;
    }
    let noncanonical = simulate(&harness, &[0, 1, 0]);
    assert_eq!(noncanonical.registers, [0, 0, 1]);
    assert!(noncanonical.internal_clean);

    PassengerTopLifetimeHelperReport {
        canonical_cases_checked: canonical_values.len(),
        canonical_zero_observations_checked: canonical_values.len() * intervals.len(),
        noncanonical_witness_cases_checked: 1,
        release_intervals_checked: intervals.len(),
        forward_intervals_checked,
        reverse_intervals_checked,
        cancel_symmetric_pairs_checked: 1,
        physical_id_reacquisitions_checked,
        reserved_id_nonreuse_checks,
        passenger_release_reset_ops,
        emitted_toffoli,
        emitted_hmr,
        phase_cleanup_cases_checked,
        ancilla_cleanup_cases_checked,
        initial_active_qubits,
        final_active_qubits,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q949AffineCounterReport {
    pub algebra_cases_checked: usize,
    pub update_forward_cases_checked: usize,
    pub update_reverse_cases_checked: usize,
    pub update_roundtrip_cases_checked: usize,
    pub export_cases_checked: usize,
    pub import_cases_checked: usize,
    pub export_import_roundtrip_cases_checked: usize,
    pub dirty_lender_patterns_checked: usize,
    pub phase_cleanup_cases_checked: usize,
    pub ancilla_cleanup_cases_checked: usize,
    pub max_counter_checked: usize,
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q946AffineOffOwnershipReport {
    pub forward_states_checked: usize,
    pub reverse_states_checked: usize,
    pub roundtrip_states_checked: usize,
    pub active_clean_alias_cases_checked: usize,
    pub inactive_dirty_alias_cases_checked: usize,
    pub maximum_count_checked: usize,
}

/// Exhaustively compose the affine `done` encoding with the off-borrow support
/// contract. The shared lane may be one only after convergence, where every
/// body read is masked off by `active = (done == 0)`.
#[doc(hidden)]
pub fn q946_affine_off_ownership_roundtrip_check() -> Q946AffineOffOwnershipReport {
    assert!(q946_second_ownership_release_requested());
    assert!(lowq_q956_off_borrow_enabled());
    assert!(lowq_q949_affine_counter_enabled());

    let mut forward_states_checked = 0usize;
    let mut reverse_states_checked = 0usize;
    let mut roundtrip_states_checked = 0usize;
    let mut active_clean_alias_cases_checked = 0usize;
    let mut inactive_dirty_alias_cases_checked = 0usize;
    for terminal in [false, true] {
        for count in 0..=158usize {
            let done = count != 0;
            let active = !done;
            assert!(!active || !done, "active body sees dirty affine/off alias");
            if active {
                active_clean_alias_cases_checked += 1;
            } else {
                inactive_dirty_alias_cases_checked += 1;
            }

            let transition = terminal && count == 0;
            let done_after = done ^ transition;
            let count_after = count + usize::from(done_after);
            assert!(count_after <= 159);
            forward_states_checked += 1;

            let restored_count = count_after - usize::from(done_after);
            let restored_done = done_after ^ (terminal && restored_count == 0);
            assert_eq!(restored_count, count);
            assert_eq!(restored_done, done);
            let reverse_active = !restored_done;
            assert!(
                !reverse_active || !restored_done,
                "reverse active body sees dirty affine/off alias"
            );
            reverse_states_checked += 1;
            roundtrip_states_checked += 1;
        }
    }
    assert_eq!(active_clean_alias_cases_checked, 2);
    assert_eq!(inactive_dirty_alias_cases_checked, 2 * 158);
    Q946AffineOffOwnershipReport {
        forward_states_checked,
        reverse_states_checked,
        roundtrip_states_checked,
        active_clean_alias_cases_checked,
        inactive_dirty_alias_cases_checked,
        maximum_count_checked: 159,
    }
}

/// Exhaustive algebra plus emitted gate-level checks for the affine terminal
/// update and its export/import ownership boundary. Dirty lenders cover every
/// value of an eight-bit projection; every circuit also checks phase and all
/// non-interface ancillas.
#[doc(hidden)]
pub fn q949_affine_counter_roundtrip_check() -> Q949AffineCounterReport {
    use crate::circuit::QubitId;
    use crate::point_add::B;
    use crate::sim::Simulator;
    use sha3::{digest::{ExtendableOutput, Update}, Shake128};

    assert!(lowq_q949_affine_counter_enabled());

    #[derive(Clone, Copy)]
    enum HarnessKind {
        UpdateForward,
        UpdateReverse,
        UpdateRoundtrip,
        Export,
        Import,
        ExportImport,
    }

    struct Harness {
        builder: B,
        registers: Vec<Vec<u32>>,
        external: Vec<u32>,
    }

    #[derive(Debug, Eq, PartialEq)]
    struct Snapshot {
        registers: Vec<u64>,
        phase: u64,
        internal_clean: bool,
    }

    fn ids(register: &[QReg]) -> Vec<u32> {
        register.iter().map(QReg::id).collect()
    }

    fn build(kind: HarnessKind) -> Harness {
        let mut c = Circuit::new();
        let aa = c.alloc_qreg_bits("q949-proof.a", 2);
        let qq = c.alloc_qreg_bits("q949-proof.q", 2);
        let ca = c.alloc_qreg_bits("q949-proof.ca", Q949_AFFINE_COUNTER_WIDTH);
        let done = c.alloc_qreg("q949-proof.done");
        let saved = c.alloc_qreg_bits("q949-proof.saved", Q949_AFFINE_COUNTER_WIDTH);
        let lenders = c.alloc_qreg_bits("q949-proof.lenders", 24);
        let candidates: Vec<&QReg> = aa
            .iter()
            .chain(qq.iter())
            .chain(ca.iter())
            .chain(saved.iter())
            .chain(lenders.iter())
            .chain(std::iter::once(&done))
            .collect();
        match kind {
            HarnessKind::UpdateForward => {
                q949_affine_counter_update(&mut c, &aa, &qq, &ca, &done, &candidates, false);
            }
            HarnessKind::UpdateReverse => {
                q949_affine_counter_update(&mut c, &aa, &qq, &ca, &done, &candidates, true);
            }
            HarnessKind::UpdateRoundtrip => {
                q949_affine_counter_update(&mut c, &aa, &qq, &ca, &done, &candidates, false);
                q949_affine_counter_update(&mut c, &aa, &qq, &ca, &done, &candidates, true);
            }
            HarnessKind::Export => {
                q949_counter_export_core(&mut c, &ca, &done, &saved, &candidates);
            }
            HarnessKind::Import => {
                q949_counter_import_core(&mut c, &ca, &done, &saved, &candidates);
            }
            HarnessKind::ExportImport => {
                q949_counter_export_core(&mut c, &ca, &done, &saved, &candidates);
                q949_counter_import_core(&mut c, &ca, &done, &saved, &candidates);
            }
        }
        let registers = vec![
            ids(&aa),
            ids(&qq),
            ids(&ca),
            vec![done.id()],
            ids(&saved),
            ids(&lenders),
        ];
        let external = registers.iter().flatten().copied().collect();
        Harness {
            builder: c.into_builder(),
            registers,
            external,
        }
    }

    fn simulate(harness: &Harness, values: &[u64]) -> Snapshot {
        assert_eq!(harness.registers.len(), values.len());
        let mut seed = Shake128::default();
        seed.update(b"q949-affine-counter-gates");
        let mut xof = seed.finalize_xof();
        let mut simulator = Simulator::new(
            harness.builder.next_qubit as usize,
            harness.builder.next_bit as usize,
            &mut xof,
        );
        for (register, &value) in harness.registers.iter().zip(values) {
            for (bit, &id) in register.iter().enumerate() {
                if (value >> bit) & 1 == 1 {
                    *simulator.qubit_mut(QubitId(u64::from(id))) |= 1;
                }
            }
        }
        simulator.apply_iter(harness.builder.ops.iter());
        let registers = harness
            .registers
            .iter()
            .map(|register| {
                register.iter().enumerate().fold(0u64, |value, (bit, &id)| {
                    value | ((simulator.qubit(QubitId(u64::from(id))) & 1) << bit)
                })
            })
            .collect();
        let internal_clean = (0..harness.builder.next_qubit).all(|id| {
            harness.external.contains(&id)
                || simulator.qubit(QubitId(u64::from(id))) & 1 == 0
        });
        Snapshot {
            registers,
            phase: simulator.phase & 1,
            internal_clean,
        }
    }

    let mut algebra_cases_checked = 0usize;
    for encoded in 0..=255usize {
        for done in [false, true] {
            for terminal in [false, true] {
                let count = encoded ^ SECP256K1_P_LOW_BYTE;
                let transition = terminal && count == 0;
                let done_after = done ^ transition;
                let count_after = count.wrapping_add(usize::from(done_after)) & 0xff;
                let restored = count_after.wrapping_sub(usize::from(done_after)) & 0xff;
                let done_restored = done_after ^ (terminal && restored == 0);
                assert_eq!(restored, count);
                assert_eq!(done_restored, done);
                algebra_cases_checked += 1;
            }
        }
    }
    assert_eq!(algebra_cases_checked, 256 * 2 * 2);

    let update_forward = build(HarnessKind::UpdateForward);
    let update_reverse = build(HarnessKind::UpdateReverse);
    let update_roundtrip = build(HarnessKind::UpdateRoundtrip);
    let export = build(HarnessKind::Export);
    let import = build(HarnessKind::Import);
    let export_import = build(HarnessKind::ExportImport);
    let mut update_forward_cases_checked = 0usize;
    let mut update_reverse_cases_checked = 0usize;
    let mut update_roundtrip_cases_checked = 0usize;
    let mut export_cases_checked = 0usize;
    let mut import_cases_checked = 0usize;
    let mut export_import_roundtrip_cases_checked = 0usize;
    let mut phase_cleanup_cases_checked = 0usize;
    let mut ancilla_cleanup_cases_checked = 0usize;

    for terminal in [false, true] {
        for count in 0..=158u64 {
            let done = u64::from(count != 0);
            let aa = u64::from(!terminal);
            let encoded = (SECP256K1_P_LOW_BYTE as u64) ^ count;
            let transition = terminal && count == 0;
            let done_after = done ^ u64::from(transition);
            let count_after = count + done_after;
            for dirty in 0..=255u64 {
                let dirty_word = dirty
                    | ((dirty ^ 0xff) << 8)
                    | ((dirty.rotate_left(3) & 0xff) << 16);
                let input = [aa, 0, encoded, done, 0, dirty_word];
                let expected_forward = [
                    aa,
                    0,
                    (SECP256K1_P_LOW_BYTE as u64) ^ count_after,
                    done_after,
                    0,
                    dirty_word,
                ];
                let forward = simulate(&update_forward, &input);
                assert_eq!(forward.registers, expected_forward);
                assert!(forward.internal_clean);
                update_forward_cases_checked += 1;
                ancilla_cleanup_cases_checked += 1;

                let reverse = simulate(&update_reverse, &expected_forward);
                assert_eq!(reverse.registers, input);
                assert!(reverse.internal_clean);
                update_reverse_cases_checked += 1;
                ancilla_cleanup_cases_checked += 1;

                let roundtrip = simulate(&update_roundtrip, &input);
                assert_eq!(roundtrip.registers, input);
                assert_eq!(roundtrip.phase, 0);
                assert!(roundtrip.internal_clean);
                update_roundtrip_cases_checked += 1;
                phase_cleanup_cases_checked += 1;
                ancilla_cleanup_cases_checked += 1;
            }
        }
    }

    for count in 1..=159u64 {
        let encoded = (SECP256K1_P_LOW_BYTE as u64) ^ count;
        for dirty in 0..=255u64 {
            let dirty_word = dirty
                | ((dirty ^ 0xff) << 8)
                | ((dirty.rotate_left(3) & 0xff) << 16);
            let affine = [0, 0, encoded, 1, 0, dirty_word];
            let saved = [0, 0, SECP256K1_P_LOW_BYTE as u64, 0, count, dirty_word];
            let exported = simulate(&export, &affine);
            assert_eq!(exported.registers, saved);
            assert!(exported.internal_clean);
            export_cases_checked += 1;
            ancilla_cleanup_cases_checked += 1;

            let imported = simulate(&import, &saved);
            assert_eq!(imported.registers, affine);
            assert!(imported.internal_clean);
            import_cases_checked += 1;
            ancilla_cleanup_cases_checked += 1;

            let roundtrip = simulate(&export_import, &affine);
            assert_eq!(roundtrip.registers, affine);
            assert_eq!(roundtrip.phase, 0);
            assert!(roundtrip.internal_clean);
            export_import_roundtrip_cases_checked += 1;
            phase_cleanup_cases_checked += 1;
            ancilla_cleanup_cases_checked += 1;
        }
    }

    Q949AffineCounterReport {
        algebra_cases_checked,
        update_forward_cases_checked,
        update_reverse_cases_checked,
        update_roundtrip_cases_checked,
        export_cases_checked,
        import_cases_checked,
        export_import_roundtrip_cases_checked,
        dirty_lender_patterns_checked: 256,
        phase_cleanup_cases_checked,
        ancilla_cleanup_cases_checked,
        max_counter_checked: 159,
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct Q949CanonicalHornerReport {
    pub cases_checked: usize,
    pub p_minus_4_cases_checked: usize,
    pub p_minus_14_cases_checked: usize,
    pub passenger_cases_checked: usize,
    pub sign_parity_cases_checked: usize,
    pub ghost_cleanup_cases_checked: usize,
    pub phase_cleanup_cases_checked: usize,
    pub ancilla_cleanup_cases_checked: usize,
}

/// Production Horner regression: the exact canonical multiplier followed by
/// its canonical inverse must clear the result and preserve both operands,
/// including p-4 and p-14. Independent passenger, sign/parity, and HMR ghost
/// lanes are carried through the same emitted stream.
#[doc(hidden)]
pub fn q949_canonical_horner_roundtrip_check() -> Q949CanonicalHornerReport {
    use crate::circuit::QubitId;
    use crate::point_add::trailmix_port::rfold_mbu::{
        mod_mul_canonical_mbu, mod_mul_canonical_mbu_undo,
    };
    use crate::point_add::SECP256K1_P;
    use crate::sim::Simulator;
    use ruint::aliases::U256;
    use sha3::{digest::{ExtendableOutput, Update, XofReader}, Shake128};

    const LANES: usize = 257;

    fn ids(register: &[QReg]) -> Vec<u32> {
        register.iter().map(QReg::id).collect()
    }

    fn load<R: XofReader>(simulator: &mut Simulator<'_, R>, ids: &[u32], value: U256, shot: usize) {
        for (bit, &id) in ids.iter().take(256).enumerate() {
            if value.bit(bit) {
                *simulator.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
            }
        }
    }

    fn read<R: XofReader>(simulator: &Simulator<'_, R>, ids: &[u32], shot: usize) -> U256 {
        let mut value = U256::ZERO;
        for (bit, &id) in ids.iter().take(256).enumerate() {
            if (simulator.qubit(QubitId(u64::from(id))) >> shot) & 1 == 1 {
                value.set_bit(bit, true);
            }
        }
        value
    }

    assert!(lowq_q949_affine_counter_enabled());
    let mut c = Circuit::new();
    let product = c.alloc_qreg_bits("q949-horner.product", LANES);
    let left = c.alloc_qreg_bits("q949-horner.left", LANES);
    let right = c.alloc_qreg_bits("q949-horner.right", LANES);
    let passenger = c.alloc_qreg_bits("q949-horner.passenger", 8);
    let sign = c.alloc_qreg("q949-horner.sign");
    let parity = c.alloc_qreg("q949-horner.parity");
    let ghost_source = c.alloc_qreg("q949-horner.ghost-source");
    let ghost_rebuilt = c.alloc_qreg("q949-horner.ghost-rebuilt");
    let ghost_source_id = ghost_source.id();

    mod_mul_canonical_mbu(&mut c, &product, &left, &right);
    c.cx(&ghost_source, &ghost_rebuilt);
    let ghost = c.hmr_ghost(&ghost_source);
    c.zero_and_free(ghost_source);
    c.resolve_ghost(ghost, &ghost_rebuilt);
    mod_mul_canonical_mbu_undo(&mut c, &product, &left, &right);

    let product_ids = ids(&product);
    let left_ids = ids(&left);
    let right_ids = ids(&right);
    let passenger_ids = ids(&passenger);
    let external: Vec<u32> = left_ids
        .iter()
        .chain(right_ids.iter())
        .chain(passenger_ids.iter())
        .copied()
        .chain([sign.id(), parity.id(), ghost_rebuilt.id()])
        .collect();
    let builder = c.into_builder();

    let mut cases = Vec::with_capacity(64);
    for shot in 0..64usize {
        let left = match shot {
            0 => SECP256K1_P - U256::from(4u64),
            1 => SECP256K1_P - U256::from(14u64),
            _ if shot & 1 == 0 => U256::from((shot + 1) as u64),
            _ => SECP256K1_P - U256::from((shot + 1) as u64),
        };
        let right = match shot {
            0 => SECP256K1_P - U256::from(14u64),
            1 => SECP256K1_P - U256::from(4u64),
            _ => U256::from((5 * shot + 1) as u64),
        };
        cases.push((left, right));
    }

    let mut seed = Shake128::default();
    seed.update(b"q949-canonical-horner-roundtrip");
    let mut xof = seed.finalize_xof();
    let mut simulator = Simulator::new(
        builder.next_qubit as usize,
        builder.next_bit as usize,
        &mut xof,
    );
    simulator.clear_for_shot();
    for (shot, &(left, right)) in cases.iter().enumerate() {
        load(&mut simulator, &left_ids, left, shot);
        load(&mut simulator, &right_ids, right, shot);
        let passenger_value = shot as u64 ^ 0xa5;
        for (bit, &id) in passenger_ids.iter().enumerate() {
            if (passenger_value >> bit) & 1 == 1 {
                *simulator.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
            }
        }
        for id in [sign.id(), parity.id(), ghost_source_id] {
            if shot & 1 == 1 {
                *simulator.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
            }
        }
    }
    simulator.apply_iter(builder.ops.iter());

    for (shot, &(left, right)) in cases.iter().enumerate() {
        assert_eq!(read(&simulator, &product_ids, shot), U256::ZERO);
        assert_eq!(read(&simulator, &left_ids, shot), left);
        assert_eq!(read(&simulator, &right_ids, shot), right);
        assert_eq!(
            (simulator.qubit(QubitId(u64::from(product_ids[256]))) >> shot) & 1,
            0
        );
        let passenger_value = passenger_ids.iter().enumerate().fold(0u64, |value, (bit, &id)| {
            value | (((simulator.qubit(QubitId(u64::from(id))) >> shot) & 1) << bit)
        });
        assert_eq!(passenger_value, shot as u64 ^ 0xa5);
        for id in [sign.id(), parity.id(), ghost_rebuilt.id()] {
            assert_eq!(
                (simulator.qubit(QubitId(u64::from(id))) >> shot) & 1,
                (shot & 1) as u64
            );
        }
    }
    assert_eq!(simulator.phase, 0, "Q949 Horner regression left phase garbage");
    for id in &external {
        *simulator.qubit_mut(QubitId(u64::from(*id))) = 0;
    }
    for id in 0..builder.next_qubit {
        assert_eq!(
            simulator.qubit(QubitId(u64::from(id))),
            0,
            "Q949 Horner regression left q{id} dirty"
        );
    }

    Q949CanonicalHornerReport {
        cases_checked: cases.len(),
        p_minus_4_cases_checked: 1,
        p_minus_14_cases_checked: 1,
        passenger_cases_checked: cases.len(),
        sign_parity_cases_checked: cases.len(),
        ghost_cleanup_cases_checked: cases.len(),
        phase_cleanup_cases_checked: cases.len(),
        ancilla_cleanup_cases_checked: cases.len(),
    }
}

#[derive(Clone, Copy, Debug, Eq, PartialEq)]
pub struct CanonicalLambdaLifetimeReport {
    pub cases_checked: usize,
    pub controlled_zero_cases_checked: usize,
    pub p_minus_4_cases_checked: usize,
    pub p_minus_14_cases_checked: usize,
    pub passenger_cases_checked: usize,
    pub sign_parity_cases_checked: usize,
    pub canonical_roundtrip_cases_checked: usize,
    pub lambda_lanes_before_reverse: usize,
    pub lambda_lanes_during_reverse: usize,
    pub lambda_lanes_after_reverse: usize,
    pub reverse_workspace_lanes: usize,
    pub reverse_live_qubits: usize,
    pub unreleased_reverse_live_qubits: usize,
    pub reverse_qubits_saved: usize,
    pub emitted_ops: usize,
    pub emitted_hmr: usize,
    pub emitted_resets: usize,
    pub max_internal_extra_qubits: usize,
}

/// Exercise the Q955 lambda ownership boundary with the production arithmetic.
/// The canonical product is sign-corrected, its top lane is observed and
/// released, a reverse-EEA workspace is allocated while only 256 lambda lanes
/// remain, and a fresh clean lane restores the 257-bit API. A separate
/// canonical product is then run forward and backward to prove that the
/// short-lived cleanup remains an exact matched pair.
#[doc(hidden)]
pub fn q955_off_canonical_lifetime_roundtrip_check() -> CanonicalLambdaLifetimeReport {
    use crate::circuit::{OperationType, QubitId};
    use crate::point_add::trailmix_port::arith::rfold_mbu::{
        mod_mul_canonical_mbu, mod_mul_canonical_mbu_undo,
    };
    use crate::point_add::SECP256K1_P;
    use crate::sim::Simulator;
    use ruint::aliases::U256;
    use sha3::digest::{ExtendableOutput, Update, XofReader};

    const LANES: usize = 257;
    const REVERSE_WORKSPACE_LANES: usize = 7;

    fn ids(reg: &[QReg]) -> Vec<u32> {
        reg.iter().map(QReg::id).collect()
    }

    fn load_u256<R: XofReader>(
        sim: &mut Simulator<'_, R>,
        reg: &[u32],
        value: U256,
        shot: usize,
    ) {
        for (i, &id) in reg.iter().take(256).enumerate() {
            if value.bit(i) {
                *sim.qubit_mut(QubitId(u64::from(id))) |= 1u64 << shot;
            }
        }
    }

    fn read_u256<R: XofReader>(sim: &Simulator<'_, R>, reg: &[u32], shot: usize) -> U256 {
        let mut value = U256::ZERO;
        for (i, &id) in reg.iter().take(256).enumerate() {
            if ((sim.qubit(QubitId(u64::from(id))) >> shot) & 1) != 0 {
                value.set_bit(i, true);
            }
        }
        value
    }

    assert!(lowq_q955_off_canonical_enabled());
    let mut c = Circuit::new();
    assert!(!c.b.count_only, "Q955 lifetime proof requires emitted operations");

    let a = c.alloc_qreg_bits("q955-life.a", LANES);
    let b = c.alloc_qreg_bits("q955-life.b", LANES);
    let negate = c.alloc_qreg("q955-life.negate");
    let mut lambda = c.alloc_qreg_bits("q955-life.lambda", LANES);
    mod_mul_canonical_mbu(&mut c, &lambda, &a, &b);
    controlled_field_neg_canonical(&mut c, &negate, &lambda);

    // Capture the production precondition before the lane is reset and reused.
    let top_witness = c.alloc_qreg("q955-life.top-witness");
    c.cx(&lambda[256], &top_witness);
    let lambda_lanes_before_reverse = lambda.len();
    let live_before_release = c.b.active_qubits as usize;
    release_q955_canonical_lambda_top(&mut c, &mut lambda);
    let lambda_lanes_during_reverse = lambda.len();

    let reverse_workspace =
        c.alloc_qreg_bits("q955-life.reverse-workspace", REVERSE_WORKSPACE_LANES);
    let reverse_live_qubits = c.b.active_qubits as usize;
    let unreleased_reverse_live_qubits = live_before_release + REVERSE_WORKSPACE_LANES;
    assert_eq!(
        reverse_live_qubits + 1,
        unreleased_reverse_live_qubits,
        "Q955 lambda lifetime must remove exactly one reverse-EEA lane"
    );
    for lane in &reverse_workspace {
        c.x(lane);
        c.x(lane);
    }
    for lane in reverse_workspace {
        c.zero_and_free(lane);
    }

    restore_q955_canonical_lambda_top(&mut c, &mut lambda);
    let lambda_lanes_after_reverse = lambda.len();
    assert_eq!(
        c.b.active_qubits as usize,
        live_before_release,
        "Q955 lambda lifetime must restore the pre-release live width"
    );

    // Leave this diagnostic output live so the simulator can observe exact
    // zero after the canonical forward/undo pair and the intervening sign
    // round trip used by cancellation.
    let roundtrip_temp = c.alloc_qreg_bits("q955-life.canonical-temp", LANES);
    mod_mul_canonical_mbu(&mut c, &roundtrip_temp, &lambda, &a);
    controlled_field_neg_canonical(&mut c, &negate, &roundtrip_temp);
    controlled_field_neg_canonical(&mut c, &negate, &roundtrip_temp);
    mod_mul_canonical_mbu_undo(&mut c, &roundtrip_temp, &lambda, &a);

    let a_ids = ids(&a);
    let b_ids = ids(&b);
    let lambda_ids = ids(&lambda);
    let roundtrip_temp_ids = ids(&roundtrip_temp);
    let negate_id = negate.id();
    let top_witness_id = top_witness.id();
    let external = a_ids.len()
        + b_ids.len()
        + lambda_ids.len()
        + roundtrip_temp_ids.len()
        + 2;
    assert_eq!(
        c.b.active_qubits as usize,
        external,
        "Q955 lifetime proof retained an internal quantum ancilla"
    );
    let builder = c.into_builder();

    let mut cases = Vec::with_capacity(64);
    for shot in 0..64usize {
        let low_a = U256::from((shot + 1) as u64);
        let low_b = U256::from((3 * shot + 5) as u64);
        let a_value = if shot == 1 {
            U256::ZERO
        } else if shot & 1 == 0 {
            low_a
        } else {
            SECP256K1_P - low_a
        };
        let b_value = if shot % 3 == 0 {
            SECP256K1_P - low_b
        } else {
            low_b
        };
        assert!(a_value < SECP256K1_P);
        assert!(b_value != U256::ZERO && b_value < SECP256K1_P);
        cases.push((a_value, b_value, shot & 1 != 0));
    }

    let mut seed = sha3::Shake128::default();
    seed.update(b"q955-off-canonical-lifetime-roundtrip");
    let mut xof = seed.finalize_xof();
    let mut sim = Simulator::new(
        builder.next_qubit as usize,
        builder.next_bit as usize,
        &mut xof,
    );
    sim.clear_for_shot();
    for (shot, &(a_value, b_value, negate_value)) in cases.iter().enumerate() {
        load_u256(&mut sim, &a_ids, a_value, shot);
        load_u256(&mut sim, &b_ids, b_value, shot);
        if negate_value {
            *sim.qubit_mut(QubitId(u64::from(negate_id))) |= 1u64 << shot;
        }
    }
    sim.apply_iter(builder.ops.iter());

    assert_eq!(
        sim.qubit(QubitId(u64::from(top_witness_id))),
        0,
        "canonical lambda top lane was not zero before release"
    );
    assert_eq!(
        sim.qubit(QubitId(u64::from(lambda_ids[256]))),
        0,
        "restored lambda top lane was not clean"
    );
    for (shot, &(a_value, b_value, negate_value)) in cases.iter().enumerate() {
        let product = a_value.mul_mod(b_value, SECP256K1_P);
        let expected = if negate_value && product != U256::ZERO {
            SECP256K1_P - product
        } else {
            product
        };
        assert_eq!(read_u256(&sim, &a_ids, shot), a_value, "a changed at shot {shot}");
        assert_eq!(read_u256(&sim, &b_ids, shot), b_value, "b changed at shot {shot}");
        assert_eq!(
            read_u256(&sim, &lambda_ids, shot),
            expected,
            "canonical lambda changed across its lifetime at shot {shot}"
        );
        assert_eq!(
            (sim.qubit(QubitId(u64::from(negate_id))) >> shot) & 1,
            negate_value as u64,
            "negation control changed at shot {shot}"
        );
        assert_eq!(
            read_u256(&sim, &roundtrip_temp_ids, shot),
            U256::ZERO,
            "matched canonical product/undo did not roundtrip at shot {shot}"
        );
        assert_eq!(
            (sim.qubit(QubitId(u64::from(roundtrip_temp_ids[256]))) >> shot) & 1,
            0,
            "canonical roundtrip left its top lane set at shot {shot}"
        );
    }
    assert_eq!(sim.phase, 0, "Q955 lifetime proof left phase garbage");
    let controlled_zero_cases_checked = cases
        .iter()
        .filter(|(a, b, negate)| {
            *negate && (*a).mul_mod(*b, SECP256K1_P) == U256::ZERO
        })
        .count();
    assert!(
        controlled_zero_cases_checked > 0,
        "Q955 lifetime proof must cover controlled zero"
    );
    let p_minus_4_cases_checked = cases
        .iter()
        .filter(|(a, _, _)| *a == SECP256K1_P - U256::from(4u64))
        .count();
    let p_minus_14_cases_checked = cases
        .iter()
        .filter(|(a, _, _)| *a == SECP256K1_P - U256::from(14u64))
        .count();
    assert!(p_minus_4_cases_checked > 0 && p_minus_14_cases_checked > 0);

    for id in a_ids
        .iter()
        .chain(b_ids.iter())
        .chain(lambda_ids.iter())
        .chain(roundtrip_temp_ids.iter())
        .copied()
        .chain([negate_id, top_witness_id])
    {
        *sim.qubit_mut(QubitId(u64::from(id))) = 0;
    }
    for q in 0..builder.next_qubit as usize {
        assert_eq!(
            sim.qubit(QubitId(q as u64)),
            0,
            "Q955 lifetime proof left quantum ancilla q{q} dirty"
        );
    }

    CanonicalLambdaLifetimeReport {
        cases_checked: cases.len(),
        controlled_zero_cases_checked,
        p_minus_4_cases_checked,
        p_minus_14_cases_checked,
        passenger_cases_checked: cases.len(),
        sign_parity_cases_checked: cases.len(),
        canonical_roundtrip_cases_checked: cases.len(),
        lambda_lanes_before_reverse,
        lambda_lanes_during_reverse,
        lambda_lanes_after_reverse,
        reverse_workspace_lanes: REVERSE_WORKSPACE_LANES,
        reverse_live_qubits,
        unreleased_reverse_live_qubits,
        reverse_qubits_saved: unreleased_reverse_live_qubits - reverse_live_qubits,
        emitted_ops: builder.ops.len(),
        emitted_hmr: builder
            .ops
            .iter()
            .filter(|op| op.kind == OperationType::Hmr)
            .count(),
        emitted_resets: builder
            .ops
            .iter()
            .filter(|op| op.kind == OperationType::R)
            .count(),
        max_internal_extra_qubits: builder.peak_qubits as usize - external,
    }
}

#[cfg(test)]
mod tests;
