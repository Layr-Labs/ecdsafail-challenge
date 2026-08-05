//! Fused double + controlled-double: `y := y * 2 * (1 + s2) mod q` with one
//! combined `(e+2d)*f` reduction instead of two separate `+f` const-adds.
//! AND-uncompute discharge is hmr+cz_if_bit; clear_and is inlined. This file
//! provides the full-clean fold (nv = L-1) plus the chunked and borrowed-dirty
//! variants (lower nv).

use super::arith::{self, F_SECP256K1};
use super::{BExt, B};
use crate::circuit::{BitId, QubitId};
use std::cell::Cell;

thread_local! {
    static FOLD_CALL_INDEX: Cell<usize> = const { Cell::new(0) };
}

pub(super) fn reset_fold_call_index() {
    FOLD_CALL_INDEX.with(|index| index.set(0));
}

fn next_fold_call_index() -> usize {
    FOLD_CALL_INDEX.with(|index| {
        let current = index.get();
        index.set(current + 1);
        current
    })
}

fn env_index_value(name: &str, index: usize) -> Option<usize> {
    std::env::var(name).ok().and_then(|value| {
        value
            .split(',')
            .filter_map(|item| item.trim().split_once(':'))
            .find_map(|(call, value)| {
                (call.parse::<usize>().ok()? == index)
                    .then(|| value.parse::<usize>().ok())
                    .flatten()
            })
    })
}

fn env_index_i32_value(name: &str, index: usize) -> Option<i32> {
    std::env::var(name).ok().and_then(|value| {
        value
            .split(',')
            .filter_map(|item| item.trim().split_once(':'))
            .find_map(|(call, value)| {
                (call.parse::<usize>().ok()? == index)
                    .then(|| value.parse::<i32>().ok())
                    .flatten()
            })
    })
}

fn fold_call_reserve(index: usize, default: usize) -> usize {
    let base = env_index_value("TLM_TARGET_FOLD_CALL_RESERVES", index).unwrap_or(default);
    env_index_value("TLM_TARGET_FOLD_CALL_RESERVE_OVERRIDES", index).unwrap_or(base)
}

/// secp256k1 `(e+2d)*f` combined-fold addend control per low-bit position `p`
/// (encodes the bit pattern of `f` and `2f`, f = 2^32+977). 0 = None.
fn fold_ctl(p: usize) -> u8 {
    match p {
        0 | 4 | 6 | 32 => 1, // E
        1 | 5 | 33 => 2,     // D
        7 => 3,              // Xor (e^d)
        8 | 9 => 4,          // Or  (e|d)
        10 => 5,             // DnotE (d&~e)
        11 => 6,             // And (e&d)
        _ => 0,
    }
}

/// MBU AND-uncompute (HMR + conditional-CZ): `t` holds `a AND b` -> |0>, phase clean.
fn clear_and(circ: &mut B, t: &QubitId, a: &QubitId, b: &QubitId) {
    let bit = circ.alloc_bit();
    circ.hmr(*t, bit);
    circ.cz_if_bit(*a, *b, bit);
}

/// Toggle `d AND NOT e` into `dne`, given the live intersection `cc = e AND d`.
/// The Boolean identity `d & !e = d ^ (e & d)` replaces one CCX with two CX.
/// This is an involution, so the same sequence clears `dne` after use.
fn toggle_dnot_e_from_intersection(circ: &mut B, d: &QubitId, cc: &QubitId, dne: &QubitId) {
    circ.cx(*d, *dne);
    circ.cx(*cc, *dne);
}

/// Carry-propagate `c` into the pure-propagation tail `y[..]` via a cascade of
/// prefix-controlled increments (`mcx_clean_k`, log* ancillae): the clean-tail
/// fold's tail [nv, L).
fn add_carry_into_tail_prefix(circ: &mut B, y: &[QubitId], c: &QubitId) {
    if std::env::var("TLM_FOLD_TAIL_CINC").ok().as_deref() == Some("1") {
        // Exact replacement for the old quadratic prefix cascade.
        let yv: Vec<QubitId> = y.to_vec();
        super::mcx::cinc_khattar_gidney(circ, &yv, c);
        return;
    }

    let t = y.len();
    for k in (1..t).rev() {
        let mut ctrls: Vec<&QubitId> = Vec::with_capacity(k + 1);
        ctrls.push(c);
        ctrls.extend(y[..k].iter());
        super::mcx::mcx_clean_k(circ, &ctrls, &y[k]);
    }
    circ.cx(*c, y[0]);
}

/// `tail_from = None` => full clean (top bit L-1 folded specially); `Some(nv)` =>
/// clean-tail: carry chain over [0, nv), then a prefix-controlled increment of the
/// pure-propagation tail [nv, L).
fn add_mf_fold_clean(circ: &mut B, e: &QubitId, d: &QubitId, y: &[QubitId]) {
    add_mf_fold_clean_tail(circ, e, d, y, None);
}

fn add_mf_fold_clean_tail(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    y: &[QubitId],
    tail_from: Option<usize>,
) {
    let l = y.len();
    assert!(l >= 2, "fold needs L >= 2");
    let loop_end = tail_from.unwrap_or(l - 1);
    const LAST_DERIVED: usize = 9;
    const LAST_AND: usize = 11;

    // Derived controls: cc = e&d, dne = d&~e, sxor = e^d, sor = e|d.
    let mut cc = Some(circ.alloc_qubit());
    circ.ccx(*e, *d, *cc.as_ref().unwrap());
    let mut dne = Some(circ.alloc_qubit());
    toggle_dnot_e_from_intersection(circ, d, cc.as_ref().unwrap(), dne.as_ref().unwrap());
    let mut sxor = Some(circ.alloc_qubit());
    circ.cx(*e, *sxor.as_ref().unwrap());
    circ.cx(*d, *sxor.as_ref().unwrap());
    let mut sor = Some(circ.alloc_qubit());
    circ.cx(*sxor.as_ref().unwrap(), *sor.as_ref().unwrap());
    circ.cx(*cc.as_ref().unwrap(), *sor.as_ref().unwrap());

    // Resolve position -> addend control qubit (None when A[p]==0).
    fn fc<'a>(
        p: usize,
        e: &'a QubitId,
        d: &'a QubitId,
        cc: Option<&'a QubitId>,
        dne: Option<&'a QubitId>,
        sx: Option<&'a QubitId>,
        so: Option<&'a QubitId>,
    ) -> Option<&'a QubitId> {
        match fold_ctl(p) {
            1 => Some(e),
            2 => Some(d),
            3 => sx,
            4 => so,
            5 => dne,
            6 => cc,
            _ => None,
        }
    }

    // Forward Gidney-clean carry chain with inline addend sums.
    let mut cy: Vec<Option<QubitId>> = Vec::with_capacity(l - 1);
    let c1 = circ.alloc_qubit();
    if let Some(a0) = fc(
        0,
        e,
        d,
        cc.as_ref(),
        dne.as_ref(),
        sxor.as_ref(),
        sor.as_ref(),
    ) {
        circ.ccx(*a0, y[0], c1);
        circ.cx(*a0, y[0]);
    }
    cy.push(Some(c1));
    for i in 1..loop_end {
        let next = circ.alloc_qubit();
        {
            let ci = cy[i - 1].as_ref().unwrap();
            circ.cx(*ci, y[i]); // y[i] ^= carry_i
            if let Some(ai) = fc(
                i,
                e,
                d,
                cc.as_ref(),
                dne.as_ref(),
                sxor.as_ref(),
                sor.as_ref(),
            ) {
                circ.cx(*ai, *ci); // carry_i ^= addend_i
            }
            circ.ccx(y[i], *ci, next);
            if let Some(ai) = fc(
                i,
                e,
                d,
                cc.as_ref(),
                dne.as_ref(),
                sxor.as_ref(),
                sor.as_ref(),
            ) {
                circ.cx(*ai, *ci);
            }
            circ.cx(*ci, next); // carry_{i+1}
            if let Some(ai) = fc(
                i,
                e,
                d,
                cc.as_ref(),
                dne.as_ref(),
                sxor.as_ref(),
                sor.as_ref(),
            ) {
                circ.cx(*ai, y[i]); // inline sum
            }
        }
        cy.push(Some(next));
        if i == LAST_DERIVED {
            let so = sor.take().unwrap();
            circ.cx(*sxor.as_ref().unwrap(), so);
            circ.cx(*cc.as_ref().unwrap(), so);
            circ.zero_and_free(so);
            let sx = sxor.take().unwrap();
            circ.cx(*e, sx);
            circ.cx(*d, sx);
            circ.zero_and_free(sx);
        }
        if i == LAST_AND {
            let dn = dne.take().unwrap();
            toggle_dnot_e_from_intersection(circ, d, cc.as_ref().unwrap(), &dn);
            circ.zero_and_free(dn);
            let c = cc.take().unwrap();
            clear_and(circ, &c, e, d);
            circ.zero_and_free(c);
        }
    }
    match tail_from {
        None => {
            // Top bit: y[L-1] += addend_{L-1} + cy_{L-1}.
            if let Some(at) = fc(
                l - 1,
                e,
                d,
                cc.as_ref(),
                dne.as_ref(),
                sxor.as_ref(),
                sor.as_ref(),
            ) {
                circ.cx(*at, y[l - 1]);
            }
            circ.cx(*cy[l - 2].as_ref().unwrap(), y[l - 1]);
        }
        Some(nv) => {
            // Pure-propagation tail [nv, L): y[nv..] += cy[nv-1]. cc/dne/sxor/sor are
            // all freed (LAST_AND/LAST_DERIVED < nv), so the mcx ancillae sit on top of
            // just the nv carries -> tail peak nv + log*(L-nv).
            add_carry_into_tail_prefix(circ, &y[nv..], cy[nv - 1].as_ref().unwrap());
        }
    }

    // Reverse: rebuild controls, AND-uncompute (hmr+cz) each carry.
    for i in (1..loop_end).rev() {
        if i == LAST_AND {
            let c = circ.alloc_qubit();
            circ.ccx(*e, *d, c);
            cc = Some(c);
            let dn = circ.alloc_qubit();
            toggle_dnot_e_from_intersection(circ, d, cc.as_ref().unwrap(), &dn);
            dne = Some(dn);
        }
        if i == LAST_DERIVED {
            let sx = circ.alloc_qubit();
            circ.cx(*e, sx);
            circ.cx(*d, sx);
            let so = circ.alloc_qubit();
            circ.cx(sx, so);
            circ.cx(*cc.as_ref().unwrap(), so);
            sxor = Some(sx);
            sor = Some(so);
        }
        if let Some(ai) = fc(
            i,
            e,
            d,
            cc.as_ref(),
            dne.as_ref(),
            sxor.as_ref(),
            sor.as_ref(),
        ) {
            circ.cx(*ai, y[i]);
        }
        let next = cy[i].take().unwrap();
        let ci = cy[i - 1].take().unwrap();
        circ.cx(ci, next);
        if let Some(ai) = fc(
            i,
            e,
            d,
            cc.as_ref(),
            dne.as_ref(),
            sxor.as_ref(),
            sor.as_ref(),
        ) {
            circ.cx(*ai, ci);
        }
        // erase next: hmr + cz_if_bit(y[i], ci).
        let bit = circ.alloc_bit();
        circ.hmr(next, bit);
        circ.zero_and_free(next);
        circ.cz_if_bit(y[i], ci, bit);
        if let Some(ai) = fc(
            i,
            e,
            d,
            cc.as_ref(),
            dne.as_ref(),
            sxor.as_ref(),
            sor.as_ref(),
        ) {
            circ.cx(*ai, ci);
            circ.cx(*ai, y[i]);
        }
        cy[i - 1] = Some(ci);
    }
    // Reverse bit 0.
    let cy1 = cy[0].take().unwrap();
    if let Some(a0) = fc(
        0,
        e,
        d,
        cc.as_ref(),
        dne.as_ref(),
        sxor.as_ref(),
        sor.as_ref(),
    ) {
        circ.cx(*a0, y[0]);
        let bit = circ.alloc_bit();
        circ.hmr(cy1, bit);
        circ.zero_and_free(cy1);
        circ.cz_if_bit(y[0], *a0, bit);
        circ.cx(*a0, y[0]);
    } else {
        circ.zero_and_free(cy1);
    }

    // Uncompute the rebuilt derived controls.
    let sx = sxor.take().unwrap();
    let so = sor.take().unwrap();
    let cc = cc.take().unwrap();
    let dne = dne.take().unwrap();
    toggle_dnot_e_from_intersection(circ, d, &cc, &dne);
    circ.zero_and_free(dne);
    circ.cx(sx, so);
    circ.cx(cc, so);
    circ.zero_and_free(so);
    circ.cx(*e, sx);
    circ.cx(*d, sx);
    circ.zero_and_free(sx);
    clear_and(circ, &cc, e, d);
    circ.zero_and_free(cc);
}

// ============================================================================
// CHUNKED fold: ceil(L/s_chunk) chunks, peak ~ s_chunk + L/s_chunk live carries
// (one chunk's internal carries plus the held boundary carries).
// ============================================================================

/// Build the 4 derived controls (e&d, e^d, e|d, d&~e).
fn build_fold_controls(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
) -> (QubitId, QubitId, QubitId, QubitId) {
    let cc = circ.alloc_qubit();
    circ.ccx(*e, *d, cc);
    let sxor = circ.alloc_qubit();
    circ.cx(*e, sxor);
    circ.cx(*d, sxor);
    let sor = circ.alloc_qubit();
    circ.cx(sxor, sor);
    circ.cx(cc, sor);
    let dne = circ.alloc_qubit();
    toggle_dnot_e_from_intersection(circ, d, &cc, &dne);
    (cc, sxor, sor, dne)
}

fn uncompute_fold_controls(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    cc: QubitId,
    sxor: QubitId,
    sor: QubitId,
    dne: QubitId,
) {
    toggle_dnot_e_from_intersection(circ, d, &cc, &dne);
    circ.zero_and_free(dne);
    circ.cx(sxor, sor);
    circ.cx(cc, sor);
    circ.zero_and_free(sor);
    circ.cx(*e, sxor);
    circ.cx(*d, sxor);
    circ.zero_and_free(sxor);
    clear_and(circ, &cc, e, d);
    circ.zero_and_free(cc);
}

/// Position -> addend control qubit map.
fn fold_ctl_map(
    e: QubitId,
    d: QubitId,
    cc: QubitId,
    sxor: QubitId,
    sor: QubitId,
    dne: QubitId,
    l: usize,
) -> Vec<Option<QubitId>> {
    (0..l)
        .map(|p| match fold_ctl(p) {
            1 => Some(e),
            2 => Some(d),
            3 => Some(sxor),
            4 => Some(sor),
            5 => Some(dne),
            6 => Some(cc),
            _ => None,
        })
        .collect()
}

/// One chunk's clean add of the fold addend (ctl) into y, threaded cin/cout.
fn fold_chunk_clean(
    circ: &mut B,
    ctl: &[Option<QubitId>],
    y: &[QubitId],
    cin: Option<&QubitId>,
    cout: &QubitId,
) {
    let s = y.len();
    if s == 0 {
        if let Some(c) = cin {
            circ.cx(*c, *cout);
        }
        return;
    }
    if std::env::var("TLM_FOLD_ZERO_CHUNK_CINC").ok().as_deref() == Some("1")
        && cin.is_some()
        && ctl.iter().all(Option::is_none)
    {
        let mut reg = y.to_vec();
        reg.push(*cout);
        super::mcx::cinc_khattar_gidney(circ, &reg, cin.expect("cin checked"));
        return;
    }
    let mut cy: Vec<Option<QubitId>> = (0..s - 1).map(|_| Some(circ.alloc_qubit())).collect();
    for i in 0..s {
        let on = ctl[i].as_ref();
        if i == 0 {
            let dst: QubitId = if s == 1 {
                *cout
            } else {
                *cy[0].as_ref().unwrap()
            };
            match cin {
                Some(c) => {
                    circ.cx(*c, y[0]);
                    if let Some(a) = on {
                        circ.cx(*a, *c);
                    }
                    circ.ccx(y[0], *c, dst);
                    if let Some(a) = on {
                        circ.cx(*a, *c);
                    }
                    circ.cx(*c, dst);
                }
                None => {
                    if let Some(a) = on {
                        circ.ccx(*a, y[0], dst);
                    }
                }
            }
        } else {
            let ci: QubitId = *cy[i - 1].as_ref().unwrap();
            let dst: QubitId = if i == s - 1 {
                *cout
            } else {
                *cy[i].as_ref().unwrap()
            };
            circ.cx(ci, y[i]);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            circ.ccx(y[i], ci, dst);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            circ.cx(ci, dst);
        }
    }
    for i in 0..s {
        if let Some(a) = ctl[i].as_ref() {
            circ.cx(*a, y[i]);
        }
    }
    for i in (0..s - 1).rev() {
        let on = ctl[i].as_ref();
        if let Some(a) = on {
            circ.cx(*a, y[i]);
        }
        let next = cy[i].take().unwrap();
        if i == 0 {
            match cin {
                Some(c) => {
                    circ.cx(*c, next);
                    if let Some(a) = on {
                        circ.cx(*a, *c);
                    }
                    let bit = circ.alloc_bit();
                    circ.hmr(next, bit);
                    circ.zero_and_free(next);
                    circ.cz_if_bit(y[0], *c, bit);
                    if let Some(a) = on {
                        circ.cx(*a, *c);
                        circ.cx(*a, y[0]);
                    }
                }
                None => {
                    let bit = circ.alloc_bit();
                    circ.hmr(next, bit);
                    circ.zero_and_free(next);
                    if let Some(a) = on {
                        circ.cz_if_bit(y[0], *a, bit);
                    }
                    if let Some(a) = on {
                        circ.cx(*a, y[0]);
                    }
                }
            }
        } else {
            let ci: QubitId = *cy[i - 1].as_ref().unwrap();
            circ.cx(ci, next);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            let bit = circ.alloc_bit();
            circ.hmr(next, bit);
            circ.zero_and_free(next);
            circ.cz_if_bit(y[i], ci, bit);
            if let Some(a) = on {
                circ.cx(*a, ci);
                circ.cx(*a, y[i]);
            }
        }
    }
}

/// Like [`fold_chunk_clean`] but DROPS the carry-out of the top bit. Used only for
/// the FINAL chunk of `add_mf_fold_chunked`, whose top bit is the fold-window top
/// (bit `lsbs-1`); its carry-out is the overflow into bit `lsbs`, which is outside
/// the window and is discarded by the same ~2^-PAD fold approximation. In the
/// cout-keeping path that carry is computed forward and then erased in reverse,
/// feeding nothing -- so dropping it is value-EQUAL (not just within tolerance)
/// while saving one boundary-carry lane (the q1132 peak-relief) plus its Toffoli.
///
/// The final chunk is never chunk 0 (it only runs when `nch > 1`), so `cin` is
/// always a real incoming boundary carry (required, not Option).
fn fold_chunk_clean_drop_cout(circ: &mut B, ctl: &[Option<QubitId>], y: &[QubitId], cin: &QubitId) {
    let s = y.len();
    if s == 0 {
        return;
    }
    if std::env::var("TLM_FOLD_ZERO_DROP_COUT_CINC_LOWANC")
        .ok()
        .as_deref()
        == Some("1")
        && ctl.iter().all(Option::is_none)
    {
        match s {
            1 => {
                circ.cx(*cin, y[0]);
                return;
            }
            2 => {
                circ.ccx(*cin, y[0], y[1]);
                circ.cx(*cin, y[0]);
                return;
            }
            3 => {
                let c01 = circ.alloc_qubit();
                circ.ccx(*cin, y[0], c01);
                circ.ccx(c01, y[1], y[2]);
                circ.ccx(*cin, y[0], c01);
                circ.zero_and_free(c01);
                circ.ccx(*cin, y[0], y[1]);
                circ.cx(*cin, y[0]);
                return;
            }
            4 => {
                let c01 = circ.alloc_qubit();
                let c012 = circ.alloc_qubit();
                circ.ccx(*cin, y[0], c01);
                circ.ccx(c01, y[1], c012);
                circ.ccx(c012, y[2], y[3]);
                circ.ccx(c01, y[1], c012);
                circ.zero_and_free(c012);
                circ.ccx(c01, y[1], y[2]);
                circ.ccx(*cin, y[0], c01);
                circ.zero_and_free(c01);
                circ.ccx(*cin, y[0], y[1]);
                circ.cx(*cin, y[0]);
                return;
            }
            _ => {}
        }
    }
    if s == 1 {
        // Top bit only: y[0] += ctl[0] + cin; carry-out dropped.
        if let Some(a) = ctl[0].as_ref() {
            circ.cx(*a, y[0]);
        }
        circ.cx(*cin, y[0]);
        return;
    }
    // s-1 internal carries: cy[i] = carry into bit i+1, for i in 0..s-1. No cout.
    let mut cy: Vec<Option<QubitId>> = (0..s - 1).map(|_| Some(circ.alloc_qubit())).collect();
    for i in 0..s - 1 {
        let on = ctl[i].as_ref();
        let dst: QubitId = *cy[i].as_ref().unwrap();
        if i == 0 {
            circ.cx(*cin, y[0]);
            if let Some(a) = on {
                circ.cx(*a, *cin);
            }
            circ.ccx(y[0], *cin, dst);
            if let Some(a) = on {
                circ.cx(*a, *cin);
            }
            circ.cx(*cin, dst);
        } else {
            let ci: QubitId = *cy[i - 1].as_ref().unwrap();
            circ.cx(ci, y[i]);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            circ.ccx(y[i], ci, dst);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            circ.cx(ci, dst);
        }
    }
    // Control sums for all bits (matches fold_chunk_clean's sum pass)...
    for i in 0..s {
        if let Some(a) = ctl[i].as_ref() {
            circ.cx(*a, y[i]);
        }
    }
    // ...plus the top bit's carry-in (the only contribution the dropped-cout step
    // would otherwise have folded into y[s-1] before computing the discarded cout).
    circ.cx(*cy[s - 2].as_ref().unwrap(), y[s - 1]);
    // Reverse: measurement-vent cy[0..s-1] (identical to fold_chunk_clean).
    for i in (0..s - 1).rev() {
        let on = ctl[i].as_ref();
        if let Some(a) = on {
            circ.cx(*a, y[i]);
        }
        let next = cy[i].take().unwrap();
        if i == 0 {
            circ.cx(*cin, next);
            if let Some(a) = on {
                circ.cx(*a, *cin);
            }
            let bit = circ.alloc_bit();
            circ.hmr(next, bit);
            circ.zero_and_free(next);
            circ.cz_if_bit(y[0], *cin, bit);
            if let Some(a) = on {
                circ.cx(*a, *cin);
                circ.cx(*a, y[0]);
            }
        } else {
            let ci: QubitId = *cy[i - 1].as_ref().unwrap();
            circ.cx(ci, next);
            if let Some(a) = on {
                circ.cx(*a, ci);
            }
            let bit = circ.alloc_bit();
            circ.hmr(next, bit);
            circ.zero_and_free(next);
            circ.cz_if_bit(y[i], ci, bit);
            if let Some(a) = on {
                circ.cx(*a, ci);
                circ.cx(*a, y[i]);
            }
        }
    }
}

/// Gated-erase a boundary carry: materialize the addend into a temp, run the
/// uncontrolled gated erase on (y, temp), un-materialize.
fn fold_boundary_erase(
    circ: &mut B,
    ctl: &[Option<QubitId>],
    y: &[QubitId],
    cin: Option<&QubitId>,
    carry: QubitId,
) {
    let erase_cap = std::env::var("TLM_FOLD_BOUNDARY_ERASE_CAP")
        .ok()
        .and_then(|value| value.parse::<usize>().ok());
    if std::env::var("TLM_FOLD_BOUNDARY_ZERO_DIRECT")
        .ok()
        .as_deref()
        == Some("1")
        && cin.is_some()
        && ctl.iter().all(Option::is_none)
    {
        fold_boundary_erase_zero_direct(circ, y, cin.expect("cin checked"), carry);
        return;
    }
    let s = y.len();
    if std::env::var("TLM_FOLD_BOUNDARY_SPARSE_ERASE")
        .ok()
        .as_deref()
        == Some("1")
        && ctl.iter().any(Option::is_some)
    {
        let mut owned_zero: Vec<QubitId> = Vec::new();
        let mut sparse: Vec<QubitId> = Vec::with_capacity(s);
        for c in ctl {
            if let Some(q) = c {
                sparse.push(*q);
            } else {
                let q = circ.alloc_qubit();
                owned_zero.push(q);
                sparse.push(q);
            }
        }
        match cin {
            Some(cin) => {
                super::arith::erase_carry_gated_opt(circ, None, y, &sparse, cin, &carry, erase_cap)
            }
            None => {
                super::arith::erase_carry_gated_zero_cin_opt(
                    circ, None, y, &sparse, &carry, erase_cap,
                );
                circ.zero_and_free(carry);
            }
        }
        for q in owned_zero {
            circ.zero_and_free(q);
        }
        return;
    }
    let temp: Vec<QubitId> = (0..s).map(|_| circ.alloc_qubit()).collect();
    for (i, c) in ctl.iter().enumerate() {
        if let Some(a) = c {
            circ.cx(*a, temp[i]);
        }
    }
    match cin {
        Some(cin) => {
            super::arith::erase_carry_gated_opt(circ, None, y, &temp, cin, &carry, erase_cap)
        }
        None => {
            super::arith::erase_carry_gated_zero_cin_opt(circ, None, y, &temp, &carry, erase_cap);
            circ.zero_and_free(carry);
        }
    }
    for (i, c) in ctl.iter().enumerate() {
        if let Some(a) = c {
            circ.cx(*a, temp[i]);
        }
    }
    for q in temp {
        circ.zero_and_free(q);
    }
}

fn fold_boundary_erase_zero_direct(circ: &mut B, y: &[QubitId], cin: &QubitId, carry: QubitId) {
    let n = y.len();
    assert!(n >= 1, "zero boundary erase needs >= 1 bit");
    let borrow_cin_c0 = std::env::var("TLM_FOLD_ZERO_DIRECT_BORROW_CIN_C0")
        .ok()
        .as_deref()
        == Some("1");
    let bit = circ.alloc_bit();
    circ.hmr(carry, bit);
    circ.zero_and_free(carry);
    circ.push_condition(bit);

    let mut cy: Vec<Option<QubitId>> = Vec::with_capacity(n);
    if borrow_cin_c0 {
        circ.x(*cin);
        cy.push(Some(*cin));
    } else {
        let c0 = circ.alloc_qubit();
        circ.x(c0);
        circ.cx(*cin, c0);
        cy.push(Some(c0));
    }
    for i in 0..n - 1 {
        let next = circ.alloc_qubit();
        let ci = cy[i].as_ref().unwrap();
        circ.cx(*ci, y[i]);
        circ.x(*ci);
        circ.ccx(y[i], *ci, next);
        circ.x(*ci);
        circ.cx(*ci, next);
        cy.push(Some(next));
    }
    {
        let i = n - 1;
        let ci = cy[i].as_ref().unwrap();
        circ.cx(*ci, y[i]);
        circ.neg();
        circ.x(*ci);
        circ.cz(y[i], *ci);
        circ.x(*ci);
        circ.z(*ci);
        circ.cx(*ci, y[i]);
    }
    for i in (0..n - 1).rev() {
        let next = cy[i + 1].take().unwrap();
        let ci = cy[i].as_ref().unwrap();
        circ.cx(*ci, next);
        let mbit = circ.alloc_bit();
        circ.hmr(next, mbit);
        circ.zero_and_free(next);
        circ.x(*ci);
        circ.cz_if_bit(y[i], *ci, mbit);
        circ.x(*ci);
        circ.cx(*ci, y[i]);
    }
    let c0 = cy[0].take().unwrap();
    if borrow_cin_c0 {
        debug_assert_eq!(c0, *cin);
        circ.x(*cin);
    } else {
        circ.cx(*cin, c0);
        circ.x(c0);
        circ.zero_and_free(c0);
    }
    circ.pop_condition();
}

/// Cheap boundary-carry erase for a ZERO-addend (all-None ctl) chunk. The forward
/// pass increments `y_chunk += cin`, so the boundary carry is exactly
/// `cout = AND(y_orig) AND cin = AND(NOT y_result) AND cin`. It therefore
/// self-uncomputes: `cout ^= AND(NOT y_result, cin)` returns it to |0> with NO
/// measurement and only log*(w) clean ancillae (`mcx_clean_k`), instead of the
/// width-w ripple comparator that `fold_boundary_erase` would otherwise hold
/// simultaneously with the other boundary carries. `y_chunk` is restored.
fn fold_boundary_erase_zero_and(circ: &mut B, y_chunk: &[QubitId], cin: &QubitId, cout: QubitId) {
    for q in y_chunk {
        circ.x(*q);
    }
    let mut ctrls: Vec<&QubitId> = y_chunk.iter().collect();
    ctrls.push(cin);
    super::mcx::mcx_clean_k(circ, &ctrls, &cout);
    for q in y_chunk {
        circ.x(*q);
    }
    circ.zero_and_free(cout);
}

fn fold_boundary_erase_zero_and_dirty(
    circ: &mut B,
    y_chunk: &[QubitId],
    cin: &QubitId,
    cout: QubitId,
    dirty: &[QubitId],
) {
    for q in y_chunk {
        circ.x(*q);
    }
    let mut ctrls: Vec<QubitId> = y_chunk.to_vec();
    ctrls.push(*cin);
    let usable_dirty: Vec<QubitId> = dirty
        .iter()
        .copied()
        .filter(|q| *q != cout && !ctrls.contains(q))
        .collect();
    toggle_mcx_with_dirty(circ, &ctrls, &usable_dirty, cout);
    for q in y_chunk {
        circ.x(*q);
    }
    circ.zero_and_free(cout);
}

fn add_mf_fold_chunked(circ: &mut B, e: &QubitId, d: &QubitId, y: &[QubitId], s_chunk: usize) {
    let l = y.len();
    let release_controls = std::env::var("TLM_FOLD_RELEASE_CONTROLS").ok().as_deref() == Some("1");
    let zero_cin = std::env::var("TLM_FOLD_CHUNK_ZERO_CIN").ok().as_deref() == Some("1");
    let mut controls = Some(build_fold_controls(circ, e, d));
    let (cc, sxor, sor, dne) = controls.expect("fold controls present");
    let mut ctl = fold_ctl_map(*e, *d, cc, sxor, sor, dne, l);
    let cin0 = (!zero_cin).then(|| circ.alloc_qubit());
    // Zero-addend (all-None ctl) runs are pure carry-propagation. With AND-erase on,
    // merge each contiguous run into ONE wide chunk: its single boundary carry is
    // AND(y_run) AND cin, erased by `fold_boundary_erase_zero_and` (log* ancillae),
    // so the run costs one held cout instead of run-width couts. Addend (Some) bits
    // stay in <= s_chunk chunks. Default-off => uniform s_chunk (byte-identical).
    let and_erase = std::env::var("TLM_FOLD_ZERO_AND_ERASE").ok().as_deref() == Some("1");
    let local_and_erase = std::env::var("TLM_FOLD_ZERO_AND_LOCAL_AND_ERASE")
        .ok()
        .as_deref()
        == Some("1");
    let dirty_and_erase = std::env::var("TLM_FOLD_ZERO_AND_DIRTY_ERASE")
        .ok()
        .as_deref()
        == Some("1");
    let uniform: Vec<(usize, usize)> = (0..l.div_ceil(s_chunk))
        .map(|j| (j * s_chunk, ((j + 1) * s_chunk).min(l)))
        .collect();
    let bounds: Vec<(usize, usize)> = if and_erase {
        // Coalesce runs of consecutive all-None uniform chunks into one wide chunk
        // (one held cout for the whole run). Mixed / all-Some chunks stay uniform.
        let mut b = Vec::new();
        let mut k = 0usize;
        while k < uniform.len() {
            let (lo, hi0) = uniform[k];
            if ctl[lo..hi0].iter().all(Option::is_none) {
                let mut hi = hi0;
                let mut m = k + 1;
                while m < uniform.len()
                    && ctl[uniform[m].0..uniform[m].1].iter().all(Option::is_none)
                {
                    hi = uniform[m].1;
                    m += 1;
                }
                b.push((lo, hi));
                k = m;
            } else {
                b.push(uniform[k]);
                k += 1;
            }
        }
        b
    } else {
        uniform
    };
    let is_zero: Vec<bool> = bounds
        .iter()
        .map(|&(lo, hi)| ctl[lo..hi].iter().all(Option::is_none))
        .collect();
    let nch = bounds.len();
    // Drop the final chunk's carry-out (the fold-window overflow, already discarded
    // by the ~2^-PAD approximation and otherwise computed-then-erased feeding
    // nothing). Value-EQUAL; saves one boundary lane at the peak. Only when nch > 1
    // (the final chunk is then never chunk 0, so it always has a real incoming cin).
    let final_no_cout =
        std::env::var("TLM_FOLD_FINAL_NO_COUT").ok().as_deref() == Some("1") && nch > 1;
    let drop_penultimate_zero_cout = std::env::var("TLM_FOLD_DROP_PENULTIMATE_ZERO_COUT")
        .ok()
        .as_deref()
        == Some("1");
    let fuse_penultimate_final_carry = std::env::var("TLM_FOLD_FUSE_PENULTIMATE_FINAL_CARRY")
        .ok()
        .as_deref()
        == Some("1");
    let fuse_two_zero_chunks_dirty = std::env::var("TLM_FOLD_FUSE_TWO_ZERO_CHUNKS_DIRTY")
        .ok()
        .as_deref()
        == Some("1");
    let last_control_chunk = 11usize.min(l - 1) / s_chunk;
    let mut boundary: Vec<QubitId> = Vec::with_capacity(nch);
    for j in 0..nch {
        let (lo, hi) = bounds[j];
        let drop_cout = final_no_cout && j + 1 == nch;
        let drop_penultimate = drop_penultimate_zero_cout
            && final_no_cout
            && j + 2 == nch
            && is_zero[j]
            && is_zero[j + 1];
        let fuse_penultimate = fuse_penultimate_final_carry
            && final_no_cout
            && j + 2 == nch
            && is_zero[j + 1]
            && bounds[j + 1].1 == bounds[j + 1].0 + 1;
        let fuse_two_zero = fuse_two_zero_chunks_dirty
            && final_no_cout
            && j + 2 == nch
            && is_zero[j]
            && is_zero[j + 1];
        if std::env::var_os("TRACE_TLM_FOLD_CHUNK").is_some() {
            let active_ctl = ctl[lo..hi].iter().filter(|c| c.is_some()).count();
            eprintln!(
                "TLM_FOLD_CHUNK dir=fwd j={j} lo={lo} hi={hi} drop_cout={drop_cout} drop_penultimate={drop_penultimate} fuse_penultimate={fuse_penultimate} active_ctl={active_ctl} controls_live={} active={} free_pool={} ops={}",
                controls.is_some(),
                circ.active_qubits,
                circ.free_qubits.len(),
                circ.current_ops_len(),
            );
        }
        if fuse_two_zero {
            // Exact two-chunk fusion.  Both chunks have zero addends.  First
            // increment the penultimate chunk modulo its width by its incoming
            // carry.  Its discarded carry is then
            //   cin AND all(NOT penultimate_result_bits).
            // Use that product directly as the control for an in-place modular
            // increment of the final chunk.  This removes the held penultimate
            // boundary lane without dropping information; all MCX scratch is
            // borrowed dirty state and restored.
            let cin = boundary[j - 1];
            let mut dirty = boundary[..j - 1].to_vec();
            dirty.push(*e);
            dirty.push(*d);
            increment_by_product_dirty(circ, &y[lo..hi], &[cin], &dirty);
            for q in &y[lo..hi] {
                circ.x(*q);
            }
            let mut carry_controls = Vec::with_capacity(1 + hi - lo);
            carry_controls.push(cin);
            carry_controls.extend_from_slice(&y[lo..hi]);
            let (final_lo, final_hi) = bounds[j + 1];
            increment_by_product_dirty(circ, &y[final_lo..final_hi], &carry_controls, &dirty);
            for q in &y[lo..hi] {
                circ.x(*q);
            }
            continue;
        }
        if fuse_two_zero_chunks_dirty
            && final_no_cout
            && j + 1 == nch
            && j >= 1
            && is_zero[j - 1]
            && is_zero[j]
        {
            continue; // handled together with the preceding zero chunk
        }
        if drop_cout
            && fuse_penultimate_final_carry
            && j >= 1
            && is_zero[j]
            && bounds[j].1 == bounds[j].0 + 1
        {
            // The preceding chunk wrote its carry directly into this final one-bit
            // zero chunk's data bit, which is exactly the final dropped-cout add.
            continue;
        }
        if drop_cout {
            if drop_penultimate_zero_cout && j >= 1 && is_zero[j] && is_zero[j - 1] {
                // Experimental low-q approximation: the previous zero chunk already
                // dropped the carry that would be this chunk's cin. The final chunk
                // is a zero-addend top tail with its own cout dropped, so treating
                // the missing cin as zero saves one live boundary carry.
                continue;
            }
            let cin = &boundary[j - 1]; // j >= 1 since nch > 1
            fold_chunk_clean_drop_cout(circ, &ctl[lo..hi], &y[lo..hi], cin);
        } else if drop_penultimate {
            let cin = if j == 0 {
                cin0.as_ref()
                    .expect("penultimate chunk cannot be chunk zero")
            } else {
                &boundary[j - 1]
            };
            fold_chunk_clean_drop_cout(circ, &ctl[lo..hi], &y[lo..hi], cin);
        } else if fuse_penultimate {
            let final_bit = y[bounds[j + 1].0];
            let cin = if j == 0 {
                cin0.as_ref()
            } else {
                Some(&boundary[j - 1])
            };
            fold_chunk_clean(circ, &ctl[lo..hi], &y[lo..hi], cin, &final_bit);
        } else {
            let cout = circ.alloc_qubit();
            {
                let cin = if j == 0 {
                    cin0.as_ref()
                } else {
                    Some(&boundary[j - 1])
                };
                fold_chunk_clean(circ, &ctl[lo..hi], &y[lo..hi], cin, &cout);
            }
            boundary.push(cout);
        }
        if release_controls && j == last_control_chunk && j + 1 < nch {
            let (cc, sxor, sor, dne) = controls.take().expect("fold controls present");
            uncompute_fold_controls(circ, e, d, cc, sxor, sor, dne);
        }
    }
    for j in (0..nch).rev() {
        if release_controls && j == last_control_chunk && controls.is_none() {
            let rebuilt = build_fold_controls(circ, e, d);
            ctl = fold_ctl_map(*e, *d, rebuilt.0, rebuilt.1, rebuilt.2, rebuilt.3, l);
            controls = Some(rebuilt);
        }
        if final_no_cout && j + 1 == nch {
            continue; // final chunk produced no boundary carry to erase
        }
        if drop_penultimate_zero_cout
            && final_no_cout
            && j + 2 == nch
            && is_zero[j]
            && is_zero[j + 1]
        {
            continue; // penultimate chunk also produced no boundary carry
        }
        if fuse_penultimate_final_carry
            && final_no_cout
            && j + 2 == nch
            && is_zero[j + 1]
            && bounds[j + 1].1 == bounds[j + 1].0 + 1
        {
            continue; // penultimate carry was folded directly into the final data bit
        }
        if fuse_two_zero_chunks_dirty
            && final_no_cout
            && j + 2 == nch
            && is_zero[j]
            && is_zero[j + 1]
        {
            continue; // exact fused pair produced no held boundary carry
        }
        let (lo, hi) = bounds[j];
        let bnd = boundary.pop().expect("boundary present");
        let cin = if j == 0 {
            cin0.as_ref()
        } else {
            Some(&boundary[j - 1])
        };
        if std::env::var_os("TRACE_TLM_FOLD_CHUNK").is_some() {
            let active_ctl = ctl[lo..hi].iter().filter(|c| c.is_some()).count();
            eprintln!(
                "TLM_FOLD_CHUNK dir=rev j={j} lo={lo} hi={hi} active_ctl={active_ctl} controls_live={} active={} free_pool={} ops={}",
                controls.is_some(),
                circ.active_qubits,
                circ.free_qubits.len(),
                circ.current_ops_len(),
            );
        }
        let zero_dirty_pool_len = j.saturating_sub(1);
        if dirty_and_erase
            && is_zero[j]
            && cin.is_some()
            && zero_dirty_pool_len >= y[lo..hi].len().saturating_sub(1)
        {
            let dirty_pool = &boundary[..zero_dirty_pool_len];
            fold_boundary_erase_zero_and_dirty(
                circ,
                &y[lo..hi],
                cin.expect("cin present"),
                bnd,
                dirty_pool,
            );
        } else if (and_erase || local_and_erase) && is_zero[j] && cin.is_some() {
            // Zero-addend run: erase its single boundary carry with the cheap
            // AND-uncompute instead of a width-w comparator.
            fold_boundary_erase_zero_and(circ, &y[lo..hi], cin.expect("cin present"), bnd);
        } else {
            fold_boundary_erase(circ, &ctl[lo..hi], &y[lo..hi], cin, bnd);
        }
    }
    if let Some(cin0) = cin0 {
        circ.zero_and_free(cin0);
    }
    let (cc, sxor, sor, dne) = controls.take().expect("fold controls restored");
    uncompute_fold_controls(circ, e, d, cc, sxor, sor, dne);
}

// ============================================================================
// GRADUAL fold (borrowed-dirty tail).
// On-demand derived controls (one live at a time) + a clean window [0,nv) handing
// a carry to a dirty body over the high bits, whose carries are stored in borrowed
// bits and discharged by measure-and-correct: hmr to a bit + z_if_bit(t,bit)
// sandwiching the carry recompute = Z^(bit . carry).
// ============================================================================

enum OnCtl {
    None,
    E,
    D,
    Owned(QubitId),
}

/// Self-inverse derived-control build/clear (involution): q ^= ctl(e,d).
fn on_ctl_apply(circ: &mut B, e: &QubitId, d: &QubitId, k: u8, q: &QubitId) {
    match k {
        3 => {
            circ.cx(*e, *q);
            circ.cx(*d, *q);
        }
        4 => {
            circ.x(*e);
            circ.x(*d);
            circ.ccx(*e, *d, *q);
            circ.x(*q);
            circ.x(*e);
            circ.x(*d);
        }
        5 => {
            circ.x(*e);
            circ.ccx(*e, *d, *q);
            circ.x(*e);
        }
        6 => circ.ccx(*e, *d, *q),
        _ => {}
    }
}

fn direct_dirty_control_enabled() -> bool {
    std::env::var("TLM_FOLD_DIRECT_DIRTY_CTL").ok().as_deref() == Some("1")
}

fn toggle_fold_ctl_into(circ: &mut B, e: &QubitId, d: &QubitId, p: usize, target: QubitId) {
    match fold_ctl(p) {
        1 => circ.cx(*e, target),
        2 => circ.cx(*d, target),
        k @ (3 | 4 | 5 | 6) => on_ctl_apply(circ, e, d, k, &target),
        _ => {}
    }
}

fn on_ctl(circ: &mut B, e: &QubitId, d: &QubitId, p: usize) -> OnCtl {
    match fold_ctl(p) {
        1 => OnCtl::E,
        2 => OnCtl::D,
        k @ (3 | 4 | 5 | 6) => {
            let q = circ.alloc_qubit();
            on_ctl_apply(circ, e, d, k, &q);
            OnCtl::Owned(q)
        }
        _ => OnCtl::None,
    }
}

fn on_ctl_ref(c: &OnCtl, e: &QubitId, d: &QubitId) -> Option<QubitId> {
    match c {
        OnCtl::None => None,
        OnCtl::E => Some(*e),
        OnCtl::D => Some(*d),
        OnCtl::Owned(q) => Some(*q),
    }
}

fn fold_ctl_linear_noanc_enabled() -> bool {
    std::env::var("TLM_DIRTY_BODY_LINEAR_NOANC").ok().as_deref() == Some("1")
}

fn fold_ctl_all_noanc_enabled() -> bool {
    std::env::var("TLM_DIRTY_BODY_ALL_NOANC").ok().as_deref() == Some("1")
}

fn fold_ctl_is_linear(p: usize) -> bool {
    matches!(fold_ctl(p), 0 | 1 | 2 | 3)
}

fn xor_linear_fold_ctl_into(circ: &mut B, e: &QubitId, d: &QubitId, p: usize, target: QubitId) {
    match fold_ctl(p) {
        1 => circ.cx(*e, target),
        2 => circ.cx(*d, target),
        3 => {
            circ.cx(*e, target);
            circ.cx(*d, target);
        }
        _ => {}
    }
}

fn xor_and_linear_fold_ctl(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    p: usize,
    other: QubitId,
    target: QubitId,
) {
    match fold_ctl(p) {
        1 => circ.ccx(*e, other, target),
        2 => circ.ccx(*d, other, target),
        3 => {
            circ.ccx(*e, other, target);
            circ.ccx(*d, other, target);
        }
        _ => {}
    }
}

fn borrowed_xor_c3(
    circ: &mut B,
    a: QubitId,
    b: QubitId,
    c: QubitId,
    target: QubitId,
    borrow: QubitId,
) {
    debug_assert_ne!(borrow, a);
    debug_assert_ne!(borrow, b);
    debug_assert_ne!(borrow, c);
    debug_assert_ne!(borrow, target);
    circ.ccx(borrow, c, target);
    circ.ccx(a, b, borrow);
    circ.ccx(borrow, c, target);
    circ.ccx(a, b, borrow);
}

fn toggle_mcx_with_dirty(circ: &mut B, controls: &[QubitId], dirty: &[QubitId], target: QubitId) {
    debug_assert!(!controls.contains(&target));
    debug_assert!(controls
        .iter()
        .enumerate()
        .all(|(index, q)| !controls[..index].contains(q)));
    match controls.len() {
        0 => circ.x(target),
        1 => circ.cx(controls[0], target),
        2 => circ.ccx(controls[0], controls[1], target),
        count => {
            assert!(
                dirty.len() >= count - 2,
                "dirty MCX needs count-2 borrowed lanes"
            );
            let bridge = dirty[0];
            debug_assert_ne!(bridge, target);
            debug_assert!(!controls.contains(&bridge));
            toggle_mcx_with_dirty(circ, &controls[..count - 1], &dirty[1..], bridge);
            circ.ccx(bridge, controls[count - 1], target);
            toggle_mcx_with_dirty(circ, &controls[..count - 1], &dirty[1..], bridge);
            circ.ccx(bridge, controls[count - 1], target);
        }
    }
}

/// Add the Boolean product of `base_controls` into `register`, modulo the
/// register width, using only borrowed-dirty scratch.  High-to-low order keeps
/// every lower register bit at its pre-increment value while it is a control.
fn increment_by_product_dirty(
    circ: &mut B,
    register: &[QubitId],
    base_controls: &[QubitId],
    dirty: &[QubitId],
) {
    for index in (0..register.len()).rev() {
        let target = register[index];
        let mut controls = Vec::with_capacity(base_controls.len() + index);
        controls.extend_from_slice(base_controls);
        controls.extend_from_slice(&register[..index]);
        let usable_dirty: Vec<QubitId> = dirty
            .iter()
            .copied()
            .filter(|q| *q != target && !controls.contains(q))
            .collect();
        toggle_mcx_with_dirty(circ, &controls, &usable_dirty, target);
    }
}

fn pick_fold_ctl_borrow(
    dirty: &[QubitId],
    e: QubitId,
    d: QubitId,
    other: QubitId,
    target: QubitId,
) -> QubitId {
    dirty
        .iter()
        .copied()
        .find(|&q| q != e && q != d && q != other && q != target)
        .expect("no borrowed dirty lane available for nonlinear fold-control term")
}

fn xor_and_fold_ctl_noanc(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    p: usize,
    other: QubitId,
    target: QubitId,
    borrow: QubitId,
) {
    match fold_ctl(p) {
        1 => circ.ccx(*e, other, target),
        2 => circ.ccx(*d, other, target),
        3 => {
            circ.ccx(*e, other, target);
            circ.ccx(*d, other, target);
        }
        4 => {
            circ.ccx(*e, other, target);
            circ.ccx(*d, other, target);
            borrowed_xor_c3(circ, *e, *d, other, target, borrow);
        }
        5 => {
            circ.ccx(*d, other, target);
            borrowed_xor_c3(circ, *e, *d, other, target, borrow);
        }
        6 => borrowed_xor_c3(circ, *e, *d, other, target, borrow),
        _ => {}
    }
}

/// Measurement-based clear for the nonlinear on-demand controls.
///
/// HMR contributes the phase `m * q`, where `m` is the measurement bit.  The
/// feedback below uses the algebraic-normal forms
///
///   e | d      = e + d + e*d
///   d & !e     = d + e*d
///   e & d      = e*d
///
/// over GF(2), so it contributes the same phase and cancels HMR exactly.
fn on_ctl_clear_nonlinear_hmr(circ: &mut B, e: &QubitId, d: &QubitId, k: u8, q: &QubitId) {
    let bit = circ.alloc_bit();
    circ.hmr(*q, bit);
    match k {
        4 => {
            circ.z_if_bit(*e, bit);
            circ.z_if_bit(*d, bit);
            circ.cz_if_bit(*e, *d, bit);
        }
        5 => {
            circ.z_if_bit(*d, bit);
            circ.cz_if_bit(*e, *d, bit);
        }
        6 => circ.cz_if_bit(*e, *d, bit),
        _ => unreachable!("HMR clear requires a nonlinear fold control"),
    }
}

fn on_ctl_free(circ: &mut B, e: &QubitId, d: &QubitId, p: usize, c: OnCtl) {
    if let OnCtl::Owned(q) = c {
        let k = fold_ctl(p);
        let hmr_disabled = std::env::var("TLM_FOLD_HMR_CONTROL_CLEANUP_DISABLE")
            .ok()
            .as_deref()
            == Some("1");
        if k == 3 || hmr_disabled {
            // XOR is cheaper reversibly; the flag preserves the exact old baseline.
            on_ctl_apply(circ, e, d, k, &q);
        } else {
            on_ctl_clear_nonlinear_hmr(circ, e, d, k, &q);
        }
        circ.zero_and_free(q);
    }
}

/// Recompute the L-1 carries of `y + A` and XOR them into `out` (the borrowed dirty
/// bits), restoring them. Per-position controls built on-demand.
fn xor_carries_perpos(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    base: usize,
    y: &[QubitId],
    out: &[QubitId],
    carry_in: Option<&QubitId>,
) {
    let n = y.len();
    fn ccx_cond(
        circ: &mut B,
        aq: Option<&QubitId>,
        c1: &QubitId,
        c2: &QubitId,
        t: &QubitId,
        g0: bool,
        g1: bool,
    ) {
        if let Some(a) = aq {
            if g0 {
                circ.cx(*a, *c1);
            }
            if g1 {
                circ.cx(*a, *c2);
            }
        }
        circ.ccx(*c1, *c2, *t);
        if let Some(a) = aq {
            if g0 {
                circ.cx(*a, *c1);
            }
            if g1 {
                circ.cx(*a, *c2);
            }
        }
    }
    for i in (1..n - 1).rev() {
        let c = on_ctl(circ, e, d, base + i);
        let aq = on_ctl_ref(&c, e, d);
        let g0 = aq.is_some();
        ccx_cond(circ, aq.as_ref(), &y[i], &out[i - 1], &out[i], g0, false);
        on_ctl_free(circ, e, d, base + i, c);
    }
    for i in 0..n - 1 {
        let c = on_ctl(circ, e, d, base + i);
        if let Some(a) = on_ctl_ref(&c, e, d) {
            circ.cx(a, out[i]);
        }
        on_ctl_free(circ, e, d, base + i, c);
    }
    {
        let c = on_ctl(circ, e, d, base);
        let aq = on_ctl_ref(&c, e, d);
        let g = aq.is_some();
        match carry_in {
            Some(cy) => ccx_cond(circ, aq.as_ref(), cy, &y[0], &out[0], g, g),
            None => {
                let cin = circ.alloc_qubit();
                ccx_cond(circ, aq.as_ref(), &cin, &y[0], &out[0], g, g);
                circ.zero_and_free(cin);
            }
        }
        on_ctl_free(circ, e, d, base, c);
    }
    for i in 1..n - 1 {
        let c = on_ctl(circ, e, d, base + i);
        let aq = on_ctl_ref(&c, e, d);
        let gi = aq.is_some();
        ccx_cond(circ, aq.as_ref(), &y[i], &out[i - 1], &out[i], gi, gi);
        on_ctl_free(circ, e, d, base + i, c);
    }
}

/// Borrowed-dirty carry-chain body. `carry_in` read-only (caller owns); `None` =>
/// carry-in 0. `dirty` (>= l-1 bits) are borrowed real-data bits used as transient
/// carry storage and restored.
fn dirty_body(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    base: usize,
    y: &[QubitId],
    dirty: &[QubitId],
    carry_in: Option<&QubitId>,
) {
    let l = y.len();
    assert!(l >= 2);
    assert!(dirty.len() >= l - 1, "need L-1 borrowed dirty bits");
    let linear_noanc = fold_ctl_linear_noanc_enabled();
    let all_noanc = fold_ctl_all_noanc_enabled();
    let first_zero_linear = carry_in.is_none() && linear_noanc && fold_ctl_is_linear(base);
    let first_zero_noanc = carry_in.is_none() && all_noanc;
    let mut cin_owned = if carry_in.is_none() && !first_zero_linear && !first_zero_noanc {
        Some(circ.alloc_qubit())
    } else {
        None
    };
    let mut bits: Vec<BitId> = Vec::with_capacity(l - 1); // bits[i] = measured cy_{i+1}
    let mut prev_new: Option<QubitId> = None;
    for i in 0..l - 1 {
        let new = circ.alloc_qubit();
        let cyi = if i == 0 {
            carry_in.copied().or_else(|| cin_owned.as_ref().copied())
        } else {
            Some(*prev_new.as_ref().unwrap())
        };
        if all_noanc {
            let borrow_y = pick_fold_ctl_borrow(dirty, *e, *d, y[i], new);
            if let Some(cyi) = cyi {
                let borrow_c = pick_fold_ctl_borrow(dirty, *e, *d, cyi, new);
                circ.ccx(y[i], cyi, new);
                xor_and_fold_ctl_noanc(circ, e, d, base + i, cyi, new, borrow_c);
            }
            xor_and_fold_ctl_noanc(circ, e, d, base + i, y[i], new, borrow_y);
            circ.cx(new, dirty[i]); // store carry copy in borrowed bit
            if let Some(cyi) = cyi {
                circ.cx(cyi, y[i]);
            }
            toggle_fold_ctl_into(circ, e, d, base + i, y[i]); // y[i] = sum_i
        } else if linear_noanc && fold_ctl_is_linear(base + i) {
            if let Some(cyi) = cyi {
                circ.ccx(y[i], cyi, new);
                xor_and_linear_fold_ctl(circ, e, d, base + i, cyi, new);
            }
            xor_and_linear_fold_ctl(circ, e, d, base + i, y[i], new);
            circ.cx(new, dirty[i]); // store carry copy in borrowed bit
            if let Some(cyi) = cyi {
                circ.cx(cyi, y[i]);
            }
            xor_linear_fold_ctl_into(circ, e, d, base + i, y[i]); // y[i] = sum_i
        } else {
            let anc = circ.alloc_qubit();
            let direct_ctl = direct_dirty_control_enabled();
            let ctlh = (!direct_ctl).then(|| on_ctl(circ, e, d, base + i));
            {
                let cyi = cyi.expect("nonlinear dirty body needs materialized carry-in");
                if direct_ctl {
                    toggle_fold_ctl_into(circ, e, d, base + i, anc);
                } else if let Some(ai) = on_ctl_ref(ctlh.as_ref().unwrap(), e, d) {
                    circ.cx(ai, anc);
                }
                circ.cx(cyi, anc);
                circ.cx(cyi, y[i]);
                circ.ccx(y[i], anc, new);
                circ.cx(cyi, new); // new = carry_{i+1}
                circ.cx(new, dirty[i]); // store carry copy in borrowed bit
                circ.cx(cyi, anc);
                if direct_ctl {
                    toggle_fold_ctl_into(circ, e, d, base + i, anc);
                    toggle_fold_ctl_into(circ, e, d, base + i, y[i]); // y[i] = sum_i
                } else if let Some(ai) = on_ctl_ref(ctlh.as_ref().unwrap(), e, d) {
                    circ.cx(ai, anc);
                    circ.cx(ai, y[i]); // y[i] = sum_i
                }
            }
            if let Some(ctlh) = ctlh {
                on_ctl_free(circ, e, d, base + i, ctlh);
            }
            circ.zero_and_free(anc);
        }
        if i == 0 {
            if let Some(c) = cin_owned.take() {
                circ.zero_and_free(c);
            }
        } else {
            let b = circ.alloc_bit();
            circ.hmr(*prev_new.as_ref().unwrap(), b);
            circ.zero_and_free(prev_new.take().unwrap());
            bits.push(b);
        }
        prev_new = Some(new);
    }
    let cy_top = prev_new.take().unwrap(); // cy_{l-1}
    {
        let topc = on_ctl(circ, e, d, base + l - 1);
        if let Some(at) = on_ctl_ref(&topc, e, d) {
            circ.cx(at, y[l - 1]);
        }
        on_ctl_free(circ, e, d, base + l - 1, topc);
    }
    circ.cx(cy_top, y[l - 1]);
    let b = circ.alloc_bit();
    circ.hmr(cy_top, b);
    circ.zero_and_free(cy_top);
    bits.push(b);

    // discharge: dirty[i] currently = orig ^ cy_{i+1}; recompute restores it to
    // orig. z_if_bit(dirty[i],bit) before+after nets Z^(bit . cy_{i+1}).
    for i in 0..l - 1 {
        circ.z_if_bit(dirty[i], bits[i]);
    }
    for q in y {
        circ.x(*q);
    }
    xor_carries_perpos(circ, e, d, base, y, dirty, carry_in);
    for q in y {
        circ.x(*q);
    }
    for i in 0..l - 1 {
        circ.z_if_bit(dirty[i], bits[i]);
    }
}

/// Clean carry-chain forward over a window, holding all b carries (carries[b-1] =
/// carry handed into the next dirty window).
fn clean_window_fwd(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    base: usize,
    y: &[QubitId],
    carries: &[QubitId],
) {
    let b = y.len();
    assert_eq!(carries.len(), b);
    {
        let c0 = on_ctl(circ, e, d, base);
        if let Some(a0) = on_ctl_ref(&c0, e, d) {
            circ.ccx(a0, y[0], carries[0]);
        }
        on_ctl_free(circ, e, d, base, c0);
    }
    for i in 1..b {
        let ci = on_ctl(circ, e, d, base + i);
        let ai = on_ctl_ref(&ci, e, d);
        circ.cx(carries[i - 1], y[i]);
        if let Some(a) = &ai {
            circ.cx(*a, carries[i - 1]);
        }
        circ.ccx(y[i], carries[i - 1], carries[i]);
        if let Some(a) = &ai {
            circ.cx(*a, carries[i - 1]);
        }
        circ.cx(carries[i - 1], carries[i]);
        on_ctl_free(circ, e, d, base + i, ci);
    }
    for i in 0..b {
        let ci = on_ctl(circ, e, d, base + i);
        if let Some(a) = on_ctl_ref(&ci, e, d) {
            circ.cx(a, y[i]);
        }
        on_ctl_free(circ, e, d, base + i, ci);
    }
}

/// Reverse of [`clean_window_fwd`]: erase all b held carries (single-term erase =
/// hmr + cz_if_bit).
fn clean_window_rev(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    base: usize,
    y: &[QubitId],
    carries: Vec<QubitId>,
) {
    let b = y.len();
    let mut cy: Vec<Option<QubitId>> = carries.into_iter().map(Some).collect();
    for i in (1..b).rev() {
        let ci_ctl = on_ctl(circ, e, d, base + i);
        let actl = on_ctl_ref(&ci_ctl, e, d);
        if let Some(ai) = &actl {
            circ.cx(*ai, y[i]);
        }
        let next = cy[i].take().unwrap();
        let ci = cy[i - 1].take().unwrap();
        circ.cx(ci, next);
        if let Some(ai) = &actl {
            circ.cx(*ai, ci);
        }
        let bit = circ.alloc_bit();
        circ.hmr(next, bit);
        circ.zero_and_free(next);
        circ.cz_if_bit(y[i], ci, bit);
        if let Some(ai) = &actl {
            circ.cx(*ai, ci);
            circ.cx(*ai, y[i]);
        }
        on_ctl_free(circ, e, d, base + i, ci_ctl);
        cy[i - 1] = Some(ci);
    }
    let cy0 = cy[0].take().unwrap();
    let c0 = on_ctl(circ, e, d, base);
    if let Some(a0) = on_ctl_ref(&c0, e, d) {
        circ.cx(a0, y[0]);
        let bit = circ.alloc_bit();
        circ.hmr(cy0, bit);
        circ.zero_and_free(cy0);
        circ.cz_if_bit(y[0], a0, bit);
        circ.cx(a0, y[0]);
    } else {
        circ.zero_and_free(cy0);
    }
    on_ctl_free(circ, e, d, base, c0);
}

/// Build the fused fold at exactly `nv` clean vents:
/// nv==L-1 => full-clean; nv>=prop_from => clean prefix-tail; else dirty gradual.
fn build_fold_at(
    circ: &mut B,
    e: &QubitId,
    d: &QubitId,
    y: &[QubitId],
    dirty: &[QubitId],
    nv: usize,
) {
    let l = y.len();
    if nv >= l - 1 {
        // nv == L-1 is full-clean; nv > L-1 only happens for the unset-schedule
        // fallback (i32::MAX) -- treat as full-clean too.
        add_mf_fold_clean(circ, e, d, y);
        return;
    }
    // prop_from = top set bit of the +f fold addend (33) + 1 = 34.
    const PROP_FROM: usize = 34;
    if nv >= 1 && nv >= PROP_FROM {
        add_mf_fold_clean_tail(circ, e, d, y, Some(nv));
        return;
    }
    if nv == 0 {
        dirty_body(circ, e, d, 0, y, dirty, None);
    } else {
        let carries: Vec<QubitId> = (0..nv).map(|_| circ.alloc_qubit()).collect();
        clean_window_fwd(circ, e, d, 0, &y[..nv], &carries);
        let cin = carries[nv - 1];
        dirty_body(circ, e, d, nv, &y[nv..], &dirty[nv..], Some(&cin));
        clean_window_rev(circ, e, d, 0, &y[..nv], carries);
    }
}

/// Dispatch the fused fold on the schedule code: -s = chunked; else nv = clean vents
/// (full-clean / clean-tail / dirty gradual via [`build_fold_at`]).
fn fused_fold(circ: &mut B, e: &QubitId, d: &QubitId, ylow: &[QubitId], dirty: &[QubitId]) {
    let call_index = next_fold_call_index();
    let timeline_start = circ.active_timeline.len();
    let entry_active = circ.active_qubits;
    let base_code = super::next_fold();
    let code = env_index_i32_value("TLM_FOLD_CALL_CODE_OVERRIDES", call_index).unwrap_or(base_code);
    let mut selected_nv = None;
    if code < 0 {
        let chunk = env_index_value("TLM_FOLD_CALL_CHUNK_OVERRIDES", call_index)
            .or_else(|| {
                std::env::var("TLM_FOLD_CHUNK_FORCE")
                    .ok()
                    .and_then(|value| value.parse::<usize>().ok())
                    .filter(|&value| value > 0)
            })
            .unwrap_or((-code) as usize);
        add_mf_fold_chunked(circ, e, d, ylow, chunk);
    } else {
        let default_reserve = std::env::var("TLM_TARGET_FOLD_RESERVE")
            .ok()
            .and_then(|value| value.parse::<usize>().ok())
            .unwrap_or(4);
        let reserve = fold_call_reserve(call_index, default_reserve);
        let nv = super::target_qubit_headroom(circ).map_or(code as usize, |headroom| {
            (code as usize).min(headroom.saturating_sub(reserve))
        });
        selected_nv = Some(nv);
        build_fold_at(circ, e, d, ylow, dirty, nv);
    }
    if std::env::var_os("TRACE_TLM_FOLD").is_some() {
        let local_peak = circ.active_timeline[timeline_start..]
            .iter()
            .map(|(_, active)| *active)
            .max()
            .unwrap_or(circ.active_qubits);
        eprintln!(
            "TLM_FOLD call={} phase={} code={} nv={} entry_active={} local_peak={} ops={}",
            call_index,
            circ.phase,
            code,
            selected_nv.map_or(-1, |value| value as i32),
            entry_active,
            local_peak,
            circ.current_ops_len(),
        );
    }
}

fn fused_fold_e_only(circ: &mut B, e: &QubitId, y: &[QubitId]) {
    let call_index = next_fold_call_index();
    let timeline_start = circ.active_timeline.len();
    let entry_active = circ.active_qubits;
    let base_code = super::next_fold();
    let code = env_index_i32_value("TLM_FOLD_CALL_CODE_OVERRIDES", call_index).unwrap_or(base_code);
    let default_reserve = std::env::var("TLM_TARGET_FOLD_RESERVE")
        .ok()
        .and_then(|value| value.parse::<usize>().ok())
        .unwrap_or(4);
    let reserve = fold_call_reserve(call_index, default_reserve);
    let g = if code < 0 {
        0
    } else {
        super::target_qubit_headroom(circ)
            .map_or(code as usize, |headroom| {
                (code as usize).min(headroom.saturating_sub(reserve))
            })
            .min(arith::lsbs() - 1)
    };
    let f_bytes = F_SECP256K1.to_le_bytes();
    let lsbs = arith::lsbs();
    super::arith::add_f_window_pub(circ, e, y, lsbs, &f_bytes, Some(g));
    if std::env::var_os("TRACE_TLM_FOLD").is_some() {
        let local_peak = circ.active_timeline[timeline_start..]
            .iter()
            .map(|(_, active)| *active)
            .max()
            .unwrap_or(circ.active_qubits);
        eprintln!(
            "TLM_FOLD call={} phase={} code={} nv={} entry_active={} local_peak={} ops={}",
            call_index,
            circ.phase,
            code,
            g as i32,
            entry_active,
            local_peak,
            circ.current_ops_len(),
        );
    }
}

fn trace_fold_alloc(circ: &B, name: &str, stage: &str, i: usize) {
    if std::env::var_os("TRACE_TLM_FOLD_ALLOC").is_some() {
        eprintln!(
            "TLM_FOLD_ALLOC name={name} stage={stage} i={i} active={} ops={}",
            circ.active_qubits,
            circ.current_ops_len(),
        );
    }
}

/// Fused double-then-controlled-double: `y := y * 2 * (1 + s2) mod q`. `y.len() == n
/// == 256`; the doubling uses two transient overflow bits (a 258-bit working view),
/// not a persistent reg slot.
pub fn fused_double_cdouble(circ: &mut B, s2: &QubitId, y: &[QubitId]) {
    maybe_run_gradual_fold_nonlinear_control_hmr_selftest();
    let n = 256usize;
    assert_eq!(
        y.len(),
        n,
        "fused double expects 256-bit y (transient overflow)"
    );
    let _ = F_SECP256K1;
    trace_fold_alloc(circ, "fwd_cdouble", "entry", usize::MAX);
    let hi = circ.alloc_qubit();
    trace_fold_alloc(circ, "fwd_cdouble", "after_hi", usize::MAX);
    let hi2 = circ.alloc_qubit();
    trace_fold_alloc(circ, "fwd_cdouble", "after_hi2", usize::MAX);
    // 258-bit view: y[0..n] ++ hi (256) ++ hi2 (257).
    let mut w: Vec<QubitId> = y.to_vec();
    w.push(hi);
    w.push(hi2);
    // shift 1 (unconditional).
    for i in (1..w.len()).rev() {
        circ.swap(w[i], w[i - 1]);
    }
    // shift 2 (s2-controlled).
    for i in (1..w.len()).rev() {
        circ.cswap(*s2, w[i], w[i - 1]);
    }
    // combined fold: add (e+2d)*f into the low LSBS window. e=w[256], d=w[257].
    // dirty borrow = the coordinate's own bits just above the fold window.
    let lsbs = arith::lsbs();
    let borrow: Vec<QubitId> = y[lsbs..2 * lsbs - 1].to_vec();
    fused_fold(circ, &w[n], &w[n + 1], &y[..lsbs], &borrow);
    // clear carry bits via bit identity (post-fold w[0]==e, w[1]==d).
    circ.cx(y[0], w[n]); // clear hi (e)
    clear_and(circ, &w[n + 1], s2, &y[1]); // clear hi2 (d = s2 & y[1])
    circ.zero_and_free(hi);
    circ.zero_and_free(hi2);
}

pub fn fused_double_only(circ: &mut B, y: &[QubitId]) {
    let n = 256usize;
    assert_eq!(y.len(), n, "fused double expects 256-bit y");
    trace_fold_alloc(circ, "fwd_only", "entry", usize::MAX);
    let hi = circ.alloc_qubit();
    trace_fold_alloc(circ, "fwd_only", "after_hi", usize::MAX);
    let mut w: Vec<QubitId> = y.to_vec();
    w.push(hi);
    for i in (1..w.len()).rev() {
        circ.swap(w[i], w[i - 1]);
    }
    fused_fold_e_only(circ, &w[n], y);
    circ.cx(y[0], w[n]);
    circ.zero_and_free(hi);
}

/// Exact gate-inverse: `y := y / (2*(1+s2)) mod q`. Reverse of [`fused_double_cdouble`]:
/// compute the overflow bits, subtract m*f, shift right.
pub fn fused_double_cdouble_reverse(circ: &mut B, s2: &QubitId, y: &[QubitId]) {
    maybe_run_gradual_fold_nonlinear_control_hmr_selftest();
    let n = 256usize;
    assert_eq!(
        y.len(),
        n,
        "fused halve expects 256-bit y (transient overflow)"
    );
    trace_fold_alloc(circ, "rev_cdouble", "entry", usize::MAX);
    let hi = circ.alloc_qubit();
    trace_fold_alloc(circ, "rev_cdouble", "after_hi", usize::MAX);
    let hi2 = circ.alloc_qubit();
    trace_fold_alloc(circ, "rev_cdouble", "after_hi2", usize::MAX);
    let mut w: Vec<QubitId> = y.to_vec();
    w.push(hi);
    w.push(hi2);
    // reversed carry-clear: compute e=y[0]->hi, d=(s2&y[1])->hi2.
    circ.ccx(*s2, y[1], w[n + 1]); // d
    circ.cx(y[0], w[n]); // e
                         // subtract m*f from the low window: X-sandwich the forward fold.
    let lsbs = arith::lsbs();
    let borrow: Vec<QubitId> = y[lsbs..2 * lsbs - 1].to_vec();
    for q in &y[..lsbs] {
        circ.x(*q);
    }
    fused_fold(circ, &w[n], &w[n + 1], &y[..lsbs], &borrow);
    for q in &y[..lsbs] {
        circ.x(*q);
    }
    // shift right (inverse of the two left shifts): s2-controlled then unconditional.
    for i in 1..w.len() {
        circ.cswap(*s2, w[i], w[i - 1]);
    }
    for i in 1..w.len() {
        circ.swap(w[i], w[i - 1]);
    }
    circ.zero_and_free(hi);
    circ.zero_and_free(hi2);
}

pub fn fused_double_only_reverse(circ: &mut B, y: &[QubitId]) {
    let n = 256usize;
    assert_eq!(y.len(), n, "fused halve expects 256-bit y");
    trace_fold_alloc(circ, "rev_only", "entry", usize::MAX);
    let hi = circ.alloc_qubit();
    trace_fold_alloc(circ, "rev_only", "after_hi", usize::MAX);
    let mut w: Vec<QubitId> = y.to_vec();
    w.push(hi);
    circ.cx(y[0], w[n]);
    let lsbs = arith::lsbs();
    for q in &y[..lsbs] {
        circ.x(*q);
    }
    fused_fold_e_only(circ, &w[n], y);
    for q in &y[..lsbs] {
        circ.x(*q);
    }
    for i in 1..w.len() {
        circ.swap(w[i], w[i - 1]);
    }
    circ.zero_and_free(hi);
}

/// Exhaust every `(e,d,HMR outcome)` basis case for each nonlinear derived
/// control.  This is available in normal builds because this worktree's wider
/// `cfg(test)` suite currently has unrelated compile failures.
fn gradual_fold_nonlinear_control_hmr_selftest() {
    use crate::circuit::OperationType;
    use crate::sim::Simulator;
    use sha3::{
        digest::{ExtendableOutput, Update},
        Shake128,
    };

    // Positions 8, 10, and 11 select OR, d&!e, and AND respectively.
    for &(position, kind) in &[(8usize, 4u8), (10, 5), (11, 6)] {
        assert_eq!(fold_ctl(position), kind);

        let mut circ = B::new();
        let e = circ.alloc_qubit();
        let d = circ.alloc_qubit();
        let q = circ.alloc_qubit();
        on_ctl_apply(&mut circ, &e, &d, kind, &q);
        on_ctl_free(&mut circ, &e, &d, position, OnCtl::Owned(q));

        assert_eq!(circ.active_qubits, 2, "owned control was not released");
        assert_eq!(circ.peak_qubits, 3, "cleanup increased peak width");
        assert_eq!(circ.next_bit, 1, "expected one HMR result bit");
        assert_eq!(
            circ.ops
                .iter()
                .filter(|op| matches!(op.kind, OperationType::CCX | OperationType::CCZ))
                .count(),
            1,
            "cleanup must add no Toffoli-class gate",
        );
        assert_eq!(
            circ.ops
                .iter()
                .filter(|op| op.kind == OperationType::Hmr)
                .count(),
            1,
        );

        // Pack every (e,d) basis state sixteen times.  The fixed SHAKE seed
        // deterministically supplies both HMR outcomes for every state; the
        // coverage assertion below keeps that part of the proof explicit.
        let mut e_mask = 0u64;
        let mut d_mask = 0u64;
        for shot in 0..64usize {
            let state = shot & 3;
            e_mask |= ((state & 1) as u64) << shot;
            d_mask |= (((state >> 1) & 1) as u64) << shot;
        }

        let mut seed = Shake128::default();
        seed.update(b"gradual-fold-derived-control-hmr");
        seed.update(&[kind]);
        let mut xof = seed.finalize_xof();
        let mut sim = Simulator::new(circ.next_qubit as usize, circ.next_bit as usize, &mut xof);
        *sim.qubit_mut(e) = e_mask;
        *sim.qubit_mut(d) = d_mask;
        sim.apply_iter(circ.ops.iter());

        assert_eq!(sim.qubit(e), e_mask, "e changed for control kind {kind}");
        assert_eq!(sim.qubit(d), d_mask, "d changed for control kind {kind}");
        assert_eq!(
            sim.qubit(q),
            0,
            "owned control remained dirty for kind {kind}"
        );
        assert_eq!(
            sim.phase, 0,
            "phase feedback failed for control kind {kind}"
        );

        let measured = sim.bits[0];
        for state in 0..4usize {
            let mut outcomes = 0u8;
            for shot in (state..64usize).step_by(4) {
                outcomes |= 1 << ((measured >> shot) & 1);
            }
            assert_eq!(
                outcomes, 0b11,
                "HMR outcomes not exhaustive for kind {kind}, state {state}",
            );
        }
    }
}

fn maybe_run_gradual_fold_nonlinear_control_hmr_selftest() {
    if std::env::var_os("TLM_FOLD_HMR_CONTROL_SELFTEST").is_none() {
        return;
    }
    static SELFTEST: std::sync::Once = std::sync::Once::new();
    SELFTEST.call_once(|| {
        gradual_fold_nonlinear_control_hmr_selftest();
        eprintln!("TLM_FOLD_HMR_CONTROL_SELFTEST_OK");
    });
}

#[cfg(test)]
mod tests {
    use super::*;

    #[test]
    fn gradual_fold_nonlinear_control_hmr_cleanup_is_exact() {
        gradual_fold_nonlinear_control_hmr_selftest();
    }
}
