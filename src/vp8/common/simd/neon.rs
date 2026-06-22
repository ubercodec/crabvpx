//! NEON backend (aarch64): the [`Simd`] primitive impl, the public per-kernel
//! entry points, and the NEON-specific sixtap filter.
//!
//! All arithmetic is safe inside `#[target_feature(enable = "neon")]` (Rust >=
//! 1.87); the only `unsafe` is register loads/stores. NEON is ARMv8-A baseline,
//! so the feature precondition always holds on the targets this compiles for.

use super::Simd;
use core::arch::aarch64::*;

pub(crate) struct Neon;

// SAFETY (whole impl): every method body calls NEON intrinsics, which are
// `unsafe` but sound here because NEON is mandatory in the ARMv8-A baseline that
// this `#[cfg(target_arch = "aarch64")]` module compiles for. The loads/stores
// additionally require the caller-guaranteed in-bounds pointers documented on
// `load_u8`/`store_u8`.
impl Simd for Neon {
    type U8 = uint8x8_t;
    type I16 = int16x8_t;

    #[inline(always)]
    unsafe fn load_u8(p: *const u8) -> uint8x8_t {
        unsafe { vld1_u8(p) }
    }
    #[inline(always)]
    unsafe fn store_u8(p: *mut u8, v: uint8x8_t) {
        unsafe { vst1_u8(p, v) }
    }

    #[inline(always)]
    fn splat_u8(x: u8) -> uint8x8_t {
        unsafe { vdup_n_u8(x) }
    }
    #[inline(always)]
    fn abd_u8(a: uint8x8_t, b: uint8x8_t) -> uint8x8_t {
        unsafe { vabd_u8(a, b) }
    }
    #[inline(always)]
    fn cgt_u8(a: uint8x8_t, b: uint8x8_t) -> uint8x8_t {
        unsafe { vcgt_u8(a, b) }
    }
    #[inline(always)]
    fn or_u8(a: uint8x8_t, b: uint8x8_t) -> uint8x8_t {
        unsafe { vorr_u8(a, b) }
    }
    #[inline(always)]
    fn not_u8(a: uint8x8_t) -> uint8x8_t {
        unsafe { vmvn_u8(a) }
    }

    #[inline(always)]
    fn widen_u8(a: uint8x8_t) -> int16x8_t {
        unsafe { vreinterpretq_s16_u16(vmovl_u8(a)) }
    }
    #[inline(always)]
    fn widen_mask(a: uint8x8_t) -> int16x8_t {
        unsafe { vmovl_s8(vreinterpret_s8_u8(a)) }
    }
    #[inline(always)]
    fn narrow_mask(a: int16x8_t) -> uint8x8_t {
        unsafe { vmovn_u16(vreinterpretq_u16_s16(a)) }
    }
    #[inline(always)]
    fn to_signed_i16(a: uint8x8_t) -> int16x8_t {
        unsafe { vmovl_s8(vreinterpret_s8_u8(veor_u8(a, vdup_n_u8(0x80)))) }
    }
    #[inline(always)]
    fn from_signed_i16(a: int16x8_t) -> uint8x8_t {
        unsafe { veor_u8(vreinterpret_u8_s8(vmovn_s16(a)), vdup_n_u8(0x80)) }
    }

    #[inline(always)]
    fn splat_i16(x: i16) -> int16x8_t {
        unsafe { vdupq_n_s16(x) }
    }
    #[inline(always)]
    fn add_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vaddq_s16(a, b) }
    }
    #[inline(always)]
    fn sub_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vsubq_s16(a, b) }
    }
    #[inline(always)]
    fn mul_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vmulq_s16(a, b) }
    }
    #[inline(always)]
    fn and_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vandq_s16(a, b) }
    }
    #[inline(always)]
    fn cgt_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vreinterpretq_s16_u16(vcgtq_s16(a, b)) }
    }
    #[inline(always)]
    fn min_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vminq_s16(a, b) }
    }
    #[inline(always)]
    fn max_i16(a: int16x8_t, b: int16x8_t) -> int16x8_t {
        unsafe { vmaxq_s16(a, b) }
    }
    #[inline(always)]
    fn shl_i16<const N: i32>(a: int16x8_t) -> int16x8_t {
        unsafe { vshlq_n_s16::<N>(a) }
    }
    #[inline(always)]
    fn shr_i16<const N: i32>(a: int16x8_t) -> int16x8_t {
        unsafe { vshrq_n_s16::<N>(a) }
    }

    #[inline(always)]
    fn transpose8x8(a: [uint8x8_t; 8]) -> [uint8x8_t; 8] {
        unsafe {
            let b0 = vtrn_u8(a[0], a[1]);
            let b1 = vtrn_u8(a[2], a[3]);
            let b2 = vtrn_u8(a[4], a[5]);
            let b3 = vtrn_u8(a[6], a[7]);
            let c0 = vtrn_u16(vreinterpret_u16_u8(b0.0), vreinterpret_u16_u8(b1.0));
            let c1 = vtrn_u16(vreinterpret_u16_u8(b0.1), vreinterpret_u16_u8(b1.1));
            let c2 = vtrn_u16(vreinterpret_u16_u8(b2.0), vreinterpret_u16_u8(b3.0));
            let c3 = vtrn_u16(vreinterpret_u16_u8(b2.1), vreinterpret_u16_u8(b3.1));
            let d0 = vtrn_u32(vreinterpret_u32_u16(c0.0), vreinterpret_u32_u16(c2.0));
            let d1 = vtrn_u32(vreinterpret_u32_u16(c1.0), vreinterpret_u32_u16(c3.0));
            let d2 = vtrn_u32(vreinterpret_u32_u16(c0.1), vreinterpret_u32_u16(c2.1));
            let d3 = vtrn_u32(vreinterpret_u32_u16(c1.1), vreinterpret_u32_u16(c3.1));
            [
                vreinterpret_u8_u32(d0.0),
                vreinterpret_u8_u32(d1.0),
                vreinterpret_u8_u32(d2.0),
                vreinterpret_u8_u32(d3.0),
                vreinterpret_u8_u32(d0.1),
                vreinterpret_u8_u32(d1.1),
                vreinterpret_u8_u32(d2.1),
                vreinterpret_u8_u32(d3.1),
            ]
        }
    }
}

// --- Public per-kernel entry points (called from the scalar dispatchers) ---

pub(crate) fn loop_filter_horizontal_edge_neon(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    count: usize,
) {
    // Y edges (count == 2, 16 px) use the s8 path; UV (count == 1) keeps the
    // generic 8-wide kernel.
    if count == 2 {
        // SAFETY: NEON baseline; the s8 path touches the same in-bounds elements.
        unsafe { loop_filter_horizontal_y_s8(s, s_offset, p, blimit, limit, thresh) };
    } else {
        super::kernels::loop_filter_horizontal_edge::<Neon>(
            s, s_offset, p, blimit, limit, thresh, count,
        );
    }
}
pub(crate) fn loop_filter_vertical_edge_neon(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    count: usize,
) {
    if count == 2 {
        // SAFETY: NEON baseline; the s8 path touches the same in-bounds elements.
        unsafe { loop_filter_vertical_y_s8(s, s_offset, p, blimit, limit, thresh) };
    } else {
        super::kernels::loop_filter_vertical_edge::<Neon>(
            s, s_offset, p, blimit, limit, thresh, count,
        );
    }
}
pub(crate) fn mbloop_filter_horizontal_edge_neon(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    count: usize,
) {
    if count == 2 {
        // SAFETY: NEON baseline; the s8 path touches the same in-bounds elements.
        unsafe { mbloop_filter_horizontal_y_s8(s, s_offset, p, blimit, limit, thresh) };
    } else {
        super::kernels::mbloop_filter_horizontal_edge::<Neon>(
            s, s_offset, p, blimit, limit, thresh, count,
        );
    }
}
pub(crate) fn mbloop_filter_vertical_edge_neon(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    count: usize,
) {
    if count == 2 {
        // SAFETY: NEON baseline; the s8 path touches the same in-bounds elements.
        unsafe { mbloop_filter_vertical_y_s8(s, s_offset, p, blimit, limit, thresh) };
    } else {
        super::kernels::mbloop_filter_vertical_edge::<Neon>(
            s, s_offset, p, blimit, limit, thresh, count,
        );
    }
}
pub(crate) fn simple_horizontal_edge_neon(
    y: &mut [u8],
    y_offset: usize,
    stride: usize,
    blimit: u8,
) {
    super::kernels::simple_horizontal_edge::<Neon>(y, y_offset, stride, blimit);
}
pub(crate) fn simple_vertical_edge_neon(y: &mut [u8], y_offset: usize, stride: usize, blimit: u8) {
    super::kernels::simple_vertical_edge::<Neon>(y, y_offset, stride, blimit);
}

// ===========================================================================
// NEON s8 loop filter (Y plane, 16-wide). The filter runs in 8-bit signed
// saturating arithmetic: `vqaddq_s8`/`vqsubq_s8` saturation IS the scalar's
// `[-128, 127]` (`vp8_signed_char_clamp`), so no widening to i16 is needed
// except the `3*(qs0 - ps0)` term. Mirrors libvpx's `vp8_loop_filter_neon`;
// bit-exact with the scalar `loopfilter_filters` reference. Used only for the
// 16-px Y edges (count == 2); UV (count == 1, 8 px) keeps the generic kernel.
// ===========================================================================

/// `vp8_filter_mask` + `vp8_hevmask`, 16 lanes. Returns `(mask, hev)` as 0xff
/// byte masks. Saturating `vqaddq_u8` for the `|p0-q0|*2 + |p1-q1|/2` term is
/// exact for the comparison: it only saturates above 255, which always exceeds
/// the (small) blimit, matching the scalar's `> blimit`.
#[target_feature(enable = "neon")]
#[allow(clippy::too_many_arguments)]
fn lf_mask_hev(
    blimit: u8,
    limit: u8,
    thresh: u8,
    p3: uint8x16_t,
    p2: uint8x16_t,
    p1: uint8x16_t,
    p0: uint8x16_t,
    q0: uint8x16_t,
    q1: uint8x16_t,
    q2: uint8x16_t,
    q3: uint8x16_t,
) -> (uint8x16_t, uint8x16_t) {
    let qlimit = vdupq_n_u8(limit);
    let qblimit = vdupq_n_u8(blimit);
    let qthresh = vdupq_n_u8(thresh);
    let c_p1p0 = vabdq_u8(p1, p0);
    let c_q1q0 = vabdq_u8(q1, q0);
    let mut m = vabdq_u8(p3, p2);
    m = vmaxq_u8(m, vabdq_u8(p2, p1));
    m = vmaxq_u8(m, c_p1p0);
    m = vmaxq_u8(m, c_q1q0);
    m = vmaxq_u8(m, vabdq_u8(q2, q1));
    m = vmaxq_u8(m, vabdq_u8(q3, q2));
    let mut mask = vcleq_u8(m, qlimit);
    let a2 = vqaddq_u8(vabdq_u8(p0, q0), vabdq_u8(p0, q0));
    let b = vshrq_n_u8(vabdq_u8(p1, q1), 1);
    mask = vandq_u8(mask, vcleq_u8(vqaddq_u8(a2, b), qblimit));
    let hev = vorrq_u8(vcgtq_u8(c_p1p0, qthresh), vcgtq_u8(c_q1q0, qthresh));
    (mask, hev)
}

/// `vp8_filter` (block edge), 16 lanes in s8. Returns new (p1, p0, q0, q1).
#[target_feature(enable = "neon")]
fn lf_normal_s8(
    mask: uint8x16_t,
    hev: uint8x16_t,
    p1: uint8x16_t,
    p0: uint8x16_t,
    q0: uint8x16_t,
    q1: uint8x16_t,
) -> (uint8x16_t, uint8x16_t, uint8x16_t, uint8x16_t) {
    let c80 = vdupq_n_u8(0x80);
    let ps1 = vreinterpretq_s8_u8(veorq_u8(p1, c80));
    let ps0 = vreinterpretq_s8_u8(veorq_u8(p0, c80));
    let qs0 = vreinterpretq_s8_u8(veorq_u8(q0, c80));
    let qs1 = vreinterpretq_s8_u8(veorq_u8(q1, c80));

    // fv = clamp(ps1 - qs1), kept only where hev.
    let mut fv = vqsubq_s8(ps1, qs1);
    fv = vreinterpretq_s8_u8(vandq_u8(vreinterpretq_u8_s8(fv), hev));
    // fv = clamp(fv + 3 * (qs0 - ps0)); the 3*d term needs i16.
    let three = vdupq_n_s16(3);
    let acc_lo = vaddw_s8(
        vmulq_s16(vsubl_s8(vget_low_s8(qs0), vget_low_s8(ps0)), three),
        vget_low_s8(fv),
    );
    let acc_hi = vaddw_s8(
        vmulq_s16(vsubl_s8(vget_high_s8(qs0), vget_high_s8(ps0)), three),
        vget_high_s8(fv),
    );
    fv = vcombine_s8(vqmovn_s16(acc_lo), vqmovn_s16(acc_hi));
    fv = vreinterpretq_s8_u8(vandq_u8(vreinterpretq_u8_s8(fv), mask));

    let f1 = vshrq_n_s8::<3>(vqaddq_s8(fv, vdupq_n_s8(4)));
    let f2 = vshrq_n_s8::<3>(vqaddq_s8(fv, vdupq_n_s8(3)));
    let nq0 = vqsubq_s8(qs0, f1);
    let np0 = vqaddq_s8(ps0, f2);
    // fv2 = (f1 + 1) >> 1 (rounding), applied only where !hev.
    let fv2 = vbicq_s8(vrshrq_n_s8::<1>(f1), vreinterpretq_s8_u8(hev));
    let nq1 = vqsubq_s8(qs1, fv2);
    let np1 = vqaddq_s8(ps1, fv2);
    (
        veorq_u8(vreinterpretq_u8_s8(np1), c80),
        veorq_u8(vreinterpretq_u8_s8(np0), c80),
        veorq_u8(vreinterpretq_u8_s8(nq0), c80),
        veorq_u8(vreinterpretq_u8_s8(nq1), c80),
    )
}

/// The `!hev` wide term `clamp((63 + fw*k) >> 7)` for the MB filter, 16 lanes.
/// `fw*k` (k in {9,18,27}) fits i16; `vqshrn_n_s16::<7>` does the `>>7` and the
/// `[-128,127]` clamp (saturating narrow). The `+63` rounding bias is preloaded.
#[target_feature(enable = "neon")]
fn lf_mb_wide(fw: int8x16_t, k: i8) -> int8x16_t {
    let bias = vdupq_n_s16(63);
    let kk = vdup_n_s8(k);
    let lo = vqshrn_n_s16::<7>(vmlal_s8(bias, vget_low_s8(fw), kk));
    let hi = vqshrn_n_s16::<7>(vmlal_s8(bias, vget_high_s8(fw), kk));
    vcombine_s8(lo, hi)
}

/// `vp8_mbfilter` (MB edge), 16 lanes in s8. Returns new (p2, p1, p0, q0, q1, q2).
#[target_feature(enable = "neon")]
fn lf_mb_s8(
    mask: uint8x16_t,
    hev: uint8x16_t,
    p2: uint8x16_t,
    p1: uint8x16_t,
    p0: uint8x16_t,
    q0: uint8x16_t,
    q1: uint8x16_t,
    q2: uint8x16_t,
) -> (
    uint8x16_t,
    uint8x16_t,
    uint8x16_t,
    uint8x16_t,
    uint8x16_t,
    uint8x16_t,
) {
    let c80 = vdupq_n_u8(0x80);
    let ps2 = vreinterpretq_s8_u8(veorq_u8(p2, c80));
    let ps1 = vreinterpretq_s8_u8(veorq_u8(p1, c80));
    let ps0 = vreinterpretq_s8_u8(veorq_u8(p0, c80));
    let qs0 = vreinterpretq_s8_u8(veorq_u8(q0, c80));
    let qs1 = vreinterpretq_s8_u8(veorq_u8(q1, c80));
    let qs2 = vreinterpretq_s8_u8(veorq_u8(q2, c80));

    // fv = clamp(clamp(ps1 - qs1) + 3 * (qs0 - ps0)) & mask.
    let fv0 = vqsubq_s8(ps1, qs1);
    let three = vdupq_n_s16(3);
    let acc_lo = vaddw_s8(
        vmulq_s16(vsubl_s8(vget_low_s8(qs0), vget_low_s8(ps0)), three),
        vget_low_s8(fv0),
    );
    let acc_hi = vaddw_s8(
        vmulq_s16(vsubl_s8(vget_high_s8(qs0), vget_high_s8(ps0)), three),
        vget_high_s8(fv0),
    );
    let fv = vcombine_s8(vqmovn_s16(acc_lo), vqmovn_s16(acc_hi));
    let fv = vreinterpretq_s8_u8(vandq_u8(vreinterpretq_u8_s8(fv), mask));

    // hev path on p0/q0.
    let fh = vreinterpretq_s8_u8(vandq_u8(vreinterpretq_u8_s8(fv), hev));
    let f1 = vshrq_n_s8::<3>(vqaddq_s8(fh, vdupq_n_s8(4)));
    let f2 = vshrq_n_s8::<3>(vqaddq_s8(fh, vdupq_n_s8(3)));
    let mut nq0 = vqsubq_s8(qs0, f1);
    let mut np0 = vqaddq_s8(ps0, f2);

    // wide path where !hev.
    let fw = vbicq_s8(fv, vreinterpretq_s8_u8(hev));
    let u = lf_mb_wide(fw, 27);
    nq0 = vqsubq_s8(nq0, u);
    np0 = vqaddq_s8(np0, u);
    let u = lf_mb_wide(fw, 18);
    let nq1 = vqsubq_s8(qs1, u);
    let np1 = vqaddq_s8(ps1, u);
    let u = lf_mb_wide(fw, 9);
    let nq2 = vqsubq_s8(qs2, u);
    let np2 = vqaddq_s8(ps2, u);

    (
        veorq_u8(vreinterpretq_u8_s8(np2), c80),
        veorq_u8(vreinterpretq_u8_s8(np1), c80),
        veorq_u8(vreinterpretq_u8_s8(np0), c80),
        veorq_u8(vreinterpretq_u8_s8(nq0), c80),
        veorq_u8(vreinterpretq_u8_s8(nq1), c80),
        veorq_u8(vreinterpretq_u8_s8(nq2), c80),
    )
}

/// Normal block-edge filter on a horizontal Y edge: 16 contiguous columns, one
/// vector per tap row. No transpose needed.
#[target_feature(enable = "neon")]
fn loop_filter_horizontal_y_s8(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    let base = s.as_mut_ptr();
    // SAFETY: same elements the 8-wide kernel touches over count=2 (idx-4p..
    // idx+3p across 16 columns); in-bounds per the bordered buffer.
    unsafe {
        let p3 = vld1q_u8(base.add(s_offset - 4 * p));
        let p2 = vld1q_u8(base.add(s_offset - 3 * p));
        let p1 = vld1q_u8(base.add(s_offset - 2 * p));
        let p0 = vld1q_u8(base.add(s_offset - p));
        let q0 = vld1q_u8(base.add(s_offset));
        let q1 = vld1q_u8(base.add(s_offset + p));
        let q2 = vld1q_u8(base.add(s_offset + 2 * p));
        let q3 = vld1q_u8(base.add(s_offset + 3 * p));
        let (mask, hev) = lf_mask_hev(blimit, limit, thresh, p3, p2, p1, p0, q0, q1, q2, q3);
        let (np1, np0, nq0, nq1) = lf_normal_s8(mask, hev, p1, p0, q0, q1);
        vst1q_u8(base.add(s_offset - 2 * p), np1);
        vst1q_u8(base.add(s_offset - p), np0);
        vst1q_u8(base.add(s_offset), nq0);
        vst1q_u8(base.add(s_offset + p), nq1);
    }
}

/// MB-edge filter on a horizontal Y edge: 16 contiguous columns, no transpose.
#[target_feature(enable = "neon")]
fn mbloop_filter_horizontal_y_s8(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    let base = s.as_mut_ptr();
    // SAFETY: same elements the 8-wide kernel touches over count=2.
    unsafe {
        let p3 = vld1q_u8(base.add(s_offset - 4 * p));
        let p2 = vld1q_u8(base.add(s_offset - 3 * p));
        let p1 = vld1q_u8(base.add(s_offset - 2 * p));
        let p0 = vld1q_u8(base.add(s_offset - p));
        let q0 = vld1q_u8(base.add(s_offset));
        let q1 = vld1q_u8(base.add(s_offset + p));
        let q2 = vld1q_u8(base.add(s_offset + 2 * p));
        let q3 = vld1q_u8(base.add(s_offset + 3 * p));
        let (mask, hev) = lf_mask_hev(blimit, limit, thresh, p3, p2, p1, p0, q0, q1, q2, q3);
        let (np2, np1, np0, nq0, nq1, nq2) = lf_mb_s8(mask, hev, p2, p1, p0, q0, q1, q2);
        vst1q_u8(base.add(s_offset - 3 * p), np2);
        vst1q_u8(base.add(s_offset - 2 * p), np1);
        vst1q_u8(base.add(s_offset - p), np0);
        vst1q_u8(base.add(s_offset), nq0);
        vst1q_u8(base.add(s_offset + p), nq1);
        vst1q_u8(base.add(s_offset + 2 * p), nq2);
    }
}

// --- s8 loop filter, vertical Y edges (16-wide via transpose) ---
// libvpx's vertical path: load 16 rows of 8 bytes, transpose to 8 taps (each a
// uint8x16 across the 16 rows), run the same 16-wide s8 filter, then store. The
// normal filter writes its 4 changed columns with `vst4_lane` (transpose on
// store); the MB filter changes 6 columns, so it transposes back and stores
// 8 bytes/row. My earlier vertical-s8 attempt washed because it transposed back
// with 8x8 transposes + vcombine round-trips; this uses libvpx's tighter scheme.

/// The 16x8 <-> 8x16 byte transpose (vtrnq u32/u16/u8). Self-inverse: used for
/// both the load (rows -> taps) and the MB store-back (taps -> rows).
#[target_feature(enable = "neon")]
fn lf_transpose_q(a: &[uint8x16_t; 8]) -> [uint8x16_t; 8] {
    let t0 = vtrnq_u32(vreinterpretq_u32_u8(a[0]), vreinterpretq_u32_u8(a[4]));
    let t1 = vtrnq_u32(vreinterpretq_u32_u8(a[1]), vreinterpretq_u32_u8(a[5]));
    let t2 = vtrnq_u32(vreinterpretq_u32_u8(a[2]), vreinterpretq_u32_u8(a[6]));
    let t3 = vtrnq_u32(vreinterpretq_u32_u8(a[3]), vreinterpretq_u32_u8(a[7]));
    let u4 = vtrnq_u16(vreinterpretq_u16_u32(t0.0), vreinterpretq_u16_u32(t2.0));
    let u5 = vtrnq_u16(vreinterpretq_u16_u32(t1.0), vreinterpretq_u16_u32(t3.0));
    let u6 = vtrnq_u16(vreinterpretq_u16_u32(t0.1), vreinterpretq_u16_u32(t2.1));
    let u7 = vtrnq_u16(vreinterpretq_u16_u32(t1.1), vreinterpretq_u16_u32(t3.1));
    let v8 = vtrnq_u8(vreinterpretq_u8_u16(u4.0), vreinterpretq_u8_u16(u5.0));
    let v9 = vtrnq_u8(vreinterpretq_u8_u16(u4.1), vreinterpretq_u8_u16(u5.1));
    let v10 = vtrnq_u8(vreinterpretq_u8_u16(u6.0), vreinterpretq_u8_u16(u7.0));
    let v11 = vtrnq_u8(vreinterpretq_u8_u16(u6.1), vreinterpretq_u8_u16(u7.1));
    [v8.0, v8.1, v9.0, v9.1, v10.0, v10.1, v11.0, v11.1]
}

/// Load the 8-byte p3..q3 window of 16 rows around a vertical edge and transpose
/// to 8 taps. `s` points at row 0, column p3 (i.e. edge - 4).
#[target_feature(enable = "neon")]
fn lf_load_vert(s: *const u8, p: usize) -> [uint8x16_t; 8] {
    // SAFETY: caller guarantees 16 rows of 8 bytes from `s` are in bounds.
    let qs = unsafe {
        [
            vcombine_u8(vld1_u8(s), vld1_u8(s.add(8 * p))),
            vcombine_u8(vld1_u8(s.add(p)), vld1_u8(s.add(9 * p))),
            vcombine_u8(vld1_u8(s.add(2 * p)), vld1_u8(s.add(10 * p))),
            vcombine_u8(vld1_u8(s.add(3 * p)), vld1_u8(s.add(11 * p))),
            vcombine_u8(vld1_u8(s.add(4 * p)), vld1_u8(s.add(12 * p))),
            vcombine_u8(vld1_u8(s.add(5 * p)), vld1_u8(s.add(13 * p))),
            vcombine_u8(vld1_u8(s.add(6 * p)), vld1_u8(s.add(14 * p))),
            vcombine_u8(vld1_u8(s.add(7 * p)), vld1_u8(s.add(15 * p))),
        ]
    };
    lf_transpose_q(&qs)
}

/// Store 4 changed columns (`a,b,c,d` = uint8x16, 16 rows) back to a vertical
/// edge at `d0` (column of the first changed tap), via `vst4_lane` per row.
#[target_feature(enable = "neon")]
fn lf_store_vert4(
    d0: *mut u8,
    p: usize,
    a: uint8x16_t,
    b: uint8x16_t,
    c: uint8x16_t,
    e: uint8x16_t,
) {
    let lo = uint8x8x4_t(
        vget_low_u8(a),
        vget_low_u8(b),
        vget_low_u8(c),
        vget_low_u8(e),
    );
    let hi = uint8x8x4_t(
        vget_high_u8(a),
        vget_high_u8(b),
        vget_high_u8(c),
        vget_high_u8(e),
    );
    // SAFETY: 4 bytes per row over 16 rows; in-bounds per the caller.
    unsafe {
        macro_rules! w4 {
            ($base:expr, $r:expr, $v:expr) => {
                vst4_lane_u8::<$r>($base.add($r * p), $v)
            };
        }
        w4!(d0, 0, lo);
        w4!(d0, 1, lo);
        w4!(d0, 2, lo);
        w4!(d0, 3, lo);
        w4!(d0, 4, lo);
        w4!(d0, 5, lo);
        w4!(d0, 6, lo);
        w4!(d0, 7, lo);
        let d1 = d0.add(8 * p);
        w4!(d1, 0, hi);
        w4!(d1, 1, hi);
        w4!(d1, 2, hi);
        w4!(d1, 3, hi);
        w4!(d1, 4, hi);
        w4!(d1, 5, hi);
        w4!(d1, 6, hi);
        w4!(d1, 7, hi);
    }
}

/// Normal block-edge filter on a vertical Y edge (16 rows, 16-wide s8).
#[target_feature(enable = "neon")]
fn loop_filter_vertical_y_s8(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    let base = s.as_mut_ptr();
    // SAFETY: the vertical edge reads s[off-4 + r*p .. +8] and writes
    // s[off-2 + r*p .. +4] over 16 rows -- the same elements the generic 8-wide
    // vertical kernel touches over count=2; in-bounds per the bordered buffer.
    let t = lf_load_vert(unsafe { base.add(s_offset - 4) as *const u8 }, p);
    let (mask, hev) = lf_mask_hev(
        blimit, limit, thresh, t[0], t[1], t[2], t[3], t[4], t[5], t[6], t[7],
    );
    let (np1, np0, nq0, nq1) = lf_normal_s8(mask, hev, t[2], t[3], t[4], t[5]);
    lf_store_vert4(unsafe { base.add(s_offset - 2) }, p, np1, np0, nq0, nq1);
}

/// MB-edge filter on a vertical Y edge: 6 columns change, so transpose back and
/// store 8 bytes/row.
#[target_feature(enable = "neon")]
fn mbloop_filter_vertical_y_s8(
    s: &mut [u8],
    s_offset: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    let base = s.as_mut_ptr();
    // SAFETY: as loop_filter_vertical_y_s8, but writes all 8 columns back.
    unsafe {
        let s0 = base.add(s_offset - 4);
        let t = lf_load_vert(s0 as *const u8, p);
        let (mask, hev) = lf_mask_hev(
            blimit, limit, thresh, t[0], t[1], t[2], t[3], t[4], t[5], t[6], t[7],
        );
        let (np2, np1, np0, nq0, nq1, nq2) =
            lf_mb_s8(mask, hev, t[1], t[2], t[3], t[4], t[5], t[6]);
        // Rebuild the 8 taps (p3 and q3 unchanged), transpose back, store rows.
        let out = lf_transpose_q(&[t[0], np2, np1, np0, nq0, nq1, nq2, t[7]]);
        for (k, q) in out.iter().enumerate() {
            vst1_u8(s0.add(k * p), vget_low_u8(*q));
            vst1_u8(s0.add((k + 8) * p), vget_high_u8(*q));
        }
    }
}

// --- s8 loop filter, UV edges with U and V packed into one 16-wide pass ---
// libvpx filters both chroma planes together: U in the low 8 lanes, V in the
// high 8. Horizontal needs no transpose (each tap row is vcombine(u_row,
// v_row)); vertical reuses lf_transpose_q (low = U's 8 rows, high = V's).

/// Horizontal UV edge: 8 tap rows, each `[u_row | v_row]`. `f_mb` selects the MB
/// filter (6 changed columns) vs the normal filter (4).
#[target_feature(enable = "neon")]
fn lf_uv_horizontal(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    f_mb: bool,
) {
    let up = u.as_mut_ptr();
    let vp = v.as_mut_ptr();
    // SAFETY: NEON baseline; rows off-4p..off+3p of u and v are in-bounds per the
    // bordered chroma buffers (same elements the 8-wide kernel touched).
    unsafe {
        // taps p3..q3 at rows off-4p .. off+3p, each [u_row | v_row].
        let t: [uint8x16_t; 8] = [
            vcombine_u8(
                vld1_u8(up.add(u_off - 4 * p)),
                vld1_u8(vp.add(v_off - 4 * p)),
            ),
            vcombine_u8(
                vld1_u8(up.add(u_off - 3 * p)),
                vld1_u8(vp.add(v_off - 3 * p)),
            ),
            vcombine_u8(
                vld1_u8(up.add(u_off - 2 * p)),
                vld1_u8(vp.add(v_off - 2 * p)),
            ),
            vcombine_u8(vld1_u8(up.add(u_off - p)), vld1_u8(vp.add(v_off - p))),
            vcombine_u8(vld1_u8(up.add(u_off)), vld1_u8(vp.add(v_off))),
            vcombine_u8(vld1_u8(up.add(u_off + p)), vld1_u8(vp.add(v_off + p))),
            vcombine_u8(
                vld1_u8(up.add(u_off + 2 * p)),
                vld1_u8(vp.add(v_off + 2 * p)),
            ),
            vcombine_u8(
                vld1_u8(up.add(u_off + 3 * p)),
                vld1_u8(vp.add(v_off + 3 * p)),
            ),
        ];
        let (mask, hev) = lf_mask_hev(
            blimit, limit, thresh, t[0], t[1], t[2], t[3], t[4], t[5], t[6], t[7],
        );
        let st = |k: usize, val: uint8x16_t| {
            vst1_u8(
                up.add((u_off as isize + (k as isize - 4) * p as isize) as usize),
                vget_low_u8(val),
            );
            vst1_u8(
                vp.add((v_off as isize + (k as isize - 4) * p as isize) as usize),
                vget_high_u8(val),
            );
        };
        if f_mb {
            let (np2, np1, np0, nq0, nq1, nq2) =
                lf_mb_s8(mask, hev, t[1], t[2], t[3], t[4], t[5], t[6]);
            st(1, np2);
            st(2, np1);
            st(3, np0);
            st(4, nq0);
            st(5, nq1);
            st(6, nq2);
        } else {
            let (np1, np0, nq0, nq1) = lf_normal_s8(mask, hev, t[2], t[3], t[4], t[5]);
            st(2, np1);
            st(3, np0);
            st(4, nq0);
            st(5, nq1);
        }
    }
}

/// Vertical UV edge: load `[u_row | v_row]` for 8 rows, transpose (low = U's 8
/// rows, high = V's), filter, transpose back, store split.
#[target_feature(enable = "neon")]
fn lf_uv_vertical(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
    f_mb: bool,
) {
    let up = u.as_mut_ptr();
    let vp = v.as_mut_ptr();
    // SAFETY: NEON baseline; cols off-4..off+3 of 8 rows of u and v are in-bounds.
    unsafe {
        let us = up.add(u_off - 4);
        let vs = vp.add(v_off - 4);
        let qs: [uint8x16_t; 8] = [
            vcombine_u8(vld1_u8(us), vld1_u8(vs)),
            vcombine_u8(vld1_u8(us.add(p)), vld1_u8(vs.add(p))),
            vcombine_u8(vld1_u8(us.add(2 * p)), vld1_u8(vs.add(2 * p))),
            vcombine_u8(vld1_u8(us.add(3 * p)), vld1_u8(vs.add(3 * p))),
            vcombine_u8(vld1_u8(us.add(4 * p)), vld1_u8(vs.add(4 * p))),
            vcombine_u8(vld1_u8(us.add(5 * p)), vld1_u8(vs.add(5 * p))),
            vcombine_u8(vld1_u8(us.add(6 * p)), vld1_u8(vs.add(6 * p))),
            vcombine_u8(vld1_u8(us.add(7 * p)), vld1_u8(vs.add(7 * p))),
        ];
        let t = lf_transpose_q(&qs);
        let (mask, hev) = lf_mask_hev(
            blimit, limit, thresh, t[0], t[1], t[2], t[3], t[4], t[5], t[6], t[7],
        );
        let out = if f_mb {
            let (np2, np1, np0, nq0, nq1, nq2) =
                lf_mb_s8(mask, hev, t[1], t[2], t[3], t[4], t[5], t[6]);
            lf_transpose_q(&[t[0], np2, np1, np0, nq0, nq1, nq2, t[7]])
        } else {
            let (np1, np0, nq0, nq1) = lf_normal_s8(mask, hev, t[2], t[3], t[4], t[5]);
            lf_transpose_q(&[t[0], t[1], np1, np0, nq0, nq1, t[6], t[7]])
        };
        for (k, q) in out.iter().enumerate() {
            vst1_u8(us.add(k * p), vget_low_u8(*q));
            vst1_u8(vs.add(k * p), vget_high_u8(*q));
        }
    }
}

pub(crate) fn loop_filter_horizontal_edge_uv_neon(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    // SAFETY: NEON baseline.
    unsafe { lf_uv_horizontal(u, u_off, v, v_off, p, blimit, limit, thresh, false) };
}

pub(crate) fn mbloop_filter_horizontal_edge_uv_neon(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    // SAFETY: NEON baseline.
    unsafe { lf_uv_horizontal(u, u_off, v, v_off, p, blimit, limit, thresh, true) };
}

pub(crate) fn loop_filter_vertical_edge_uv_neon(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    // SAFETY: NEON baseline.
    unsafe { lf_uv_vertical(u, u_off, v, v_off, p, blimit, limit, thresh, false) };
}

pub(crate) fn mbloop_filter_vertical_edge_uv_neon(
    u: &mut [u8],
    u_off: usize,
    v: &mut [u8],
    v_off: usize,
    p: usize,
    blimit: u8,
    limit: u8,
    thresh: u8,
) {
    // SAFETY: NEON baseline.
    unsafe { lf_uv_vertical(u, u_off, v, v_off, p, blimit, limit, thresh, true) };
}

// ===========================================================================
// NEON dequant + 4x4 IDCT + add, processing TWO horizontally-adjacent blocks at
// once (libvpx's idct_dequant_full_2x / _0_2x). Twice the throughput per
// instruction vs a per-block kernel; the per-block version was perf-neutral
// because per-block dispatch dominated. i16 saturating arithmetic, `vqdmulhq`
// for the cospi/sinpi constants (same scheme as the per-block idct). The two
// paired blocks are adjacent in `dst`, so each of the 4 transform rows is 8
// contiguous bytes (block0 cols 0..4 ++ block1 cols 0..4). Bit-exact with the
// scalar reference on real streams (62-vector differential is the gate); the
// saturating i16 domain matches scalar i32 for valid dequantized coefficients.
// ===========================================================================

const IDCT_COSPI: i16 = 20091;
const IDCT_SINPI_H: i16 = 17734; // sinpi8sqrt2 (35468) >> 1; doubled back by vqdmulhq

/// One IDCT butterfly pass over two blocks at once (8 lanes = 2 blocks × 4 cols).
#[target_feature(enable = "neon")]
fn idct2x_pass(
    row0: int16x8_t,
    row1: int16x8_t,
    row2: int16x8_t,
    row3: int16x8_t,
) -> (int16x8_t, int16x8_t, int16x8_t, int16x8_t) {
    let a1 = vqaddq_s16(row0, row2);
    let b1 = vqsubq_s16(row0, row2);
    let t1 = vqaddq_s16(row1, vshrq_n_s16::<1>(vqdmulhq_n_s16(row1, IDCT_COSPI)));
    let t3 = vqaddq_s16(row3, vshrq_n_s16::<1>(vqdmulhq_n_s16(row3, IDCT_COSPI)));
    let c1 = vqsubq_s16(vqdmulhq_n_s16(row1, IDCT_SINPI_H), t3);
    let d1 = vqaddq_s16(t1, vqdmulhq_n_s16(row3, IDCT_SINPI_H));
    (
        vqaddq_s16(a1, d1),
        vqaddq_s16(b1, c1),
        vqsubq_s16(b1, c1),
        vqsubq_s16(a1, d1),
    )
}

/// 4x4 transpose of both blocks in parallel (`vtrnq` does each 4-lane half).
/// Returns the four transposed rows in order.
#[target_feature(enable = "neon")]
fn idct2x_transpose(
    a: int16x8_t,
    b: int16x8_t,
    c: int16x8_t,
    d: int16x8_t,
) -> (int16x8_t, int16x8_t, int16x8_t, int16x8_t) {
    let t0 = vtrnq_s32(vreinterpretq_s32_s16(a), vreinterpretq_s32_s16(c));
    let t1 = vtrnq_s32(vreinterpretq_s32_s16(b), vreinterpretq_s32_s16(d));
    let u0 = vtrnq_s16(vreinterpretq_s16_s32(t0.0), vreinterpretq_s16_s32(t1.0));
    let u1 = vtrnq_s16(vreinterpretq_s16_s32(t0.1), vreinterpretq_s16_s32(t1.1));
    (u0.0, u0.1, u1.0, u1.1)
}

/// Add an 8-wide residual row to the 8 predictor bytes at `dst + r*stride`,
/// clamp, and store. (u16-wrap add + `vqmovun_s16` == `clamp(res + pred, 0, 255)`.)
#[target_feature(enable = "neon")]
fn idct2x_store_row(dst: &mut [u8], off: usize, res: int16x8_t) {
    // SAFETY: callers guarantee 8 valid bytes at `dst[off..off+8]`.
    unsafe {
        let pred = vld1_u8(dst.as_ptr().add(off));
        let sum = vqmovun_s16(vreinterpretq_s16_u16(vaddw_u8(
            vreinterpretq_u16_s16(res),
            pred,
        )));
        vst1_u8(dst.as_mut_ptr().add(off), sum);
    }
}

/// Full dequant+IDCT+add for two adjacent blocks (`q[0..16]` -> `dst` cols 0..4,
/// `q[16..32]` -> `dst` cols 4..8). Clears the 32 processed coefficients.
#[target_feature(enable = "neon")]
fn idct_dequant_full_2x(q: &mut [i16], dq: &[i16; 16], dst: &mut [u8], stride: usize) {
    // SAFETY: NEON baseline; q has >= 32 elems, dq is [i16;16], rows are in-bounds.
    let (row0, row1, row2, row3) = unsafe {
        let dq0 = vld1q_s16(dq.as_ptr());
        let dq1 = vld1q_s16(dq.as_ptr().add(8));
        let b0r01 = vmulq_s16(vld1q_s16(q.as_ptr()), dq0);
        let b0r23 = vmulq_s16(vld1q_s16(q.as_ptr().add(8)), dq1);
        let b1r01 = vmulq_s16(vld1q_s16(q.as_ptr().add(16)), dq0);
        let b1r23 = vmulq_s16(vld1q_s16(q.as_ptr().add(24)), dq1);
        // Interleave so each row holds [block0 4 cols, block1 4 cols].
        (
            vcombine_s16(vget_low_s16(b0r01), vget_low_s16(b1r01)),
            vcombine_s16(vget_high_s16(b0r01), vget_high_s16(b1r01)),
            vcombine_s16(vget_low_s16(b0r23), vget_low_s16(b1r23)),
            vcombine_s16(vget_high_s16(b0r23), vget_high_s16(b1r23)),
        )
    };
    let (o0, o1, o2, o3) = idct2x_pass(row0, row1, row2, row3);
    let (t0, t1, t2, t3) = idct2x_transpose(o0, o1, o2, o3);
    let (p0, p1, p2, p3) = idct2x_pass(t0, t1, t2, t3);
    let (f0, f1, f2, f3) = idct2x_transpose(
        vrshrq_n_s16::<3>(p0),
        vrshrq_n_s16::<3>(p1),
        vrshrq_n_s16::<3>(p2),
        vrshrq_n_s16::<3>(p3),
    );
    idct2x_store_row(dst, 0, f0);
    idct2x_store_row(dst, stride, f1);
    idct2x_store_row(dst, 2 * stride, f2);
    idct2x_store_row(dst, 3 * stride, f3);
    q[..32].fill(0);
}

/// DC-only dequant+add for two adjacent blocks: add `(q[0]*dq + 4) >> 3` to
/// block0 and `(q[16]*dq + 4) >> 3` to block1, each over its 4x4.
#[target_feature(enable = "neon")]
fn idct_dequant_0_2x(q: &mut [i16], dq0: i16, dst: &mut [u8], stride: usize) {
    let a0 = (((q[0] as i32) * (dq0 as i32) + 4) >> 3) as i16;
    let a1 = (((q[16] as i32) * (dq0 as i32) + 4) >> 3) as i16;
    q[0] = 0;
    q[16] = 0;
    let add = vcombine_s16(vdup_n_s16(a0), vdup_n_s16(a1)); // [a0;4, a1;4]
    for r in 0..4 {
        idct2x_store_row(dst, r * stride, add);
    }
}

/// Driver for the 16 luma blocks: process horizontally-adjacent pairs, choosing
/// the full transform if either block has AC coefficients (eob > 1), the DC-only
/// path if either has only DC, and skipping empty pairs. Mirrors libvpx's
/// `vp8_dequant_idct_add_y_block_neon`.
pub(crate) fn vp8_dequant_idct_add_y_block_neon(
    q: &mut [i16; 256],
    dq: &[i16; 16],
    dst: &mut [u8],
    stride: usize,
    eobs: &[i8; 16],
) {
    for row in 0..4 {
        for pair in 0..2 {
            let blk = row * 4 + pair * 2;
            let (ea, eb) = (eobs[blk], eobs[blk + 1]);
            let dst_off = row * 4 * stride + pair * 8;
            let q_off = blk * 16;
            // SAFETY: NEON baseline on aarch64.
            unsafe {
                if ea > 1 || eb > 1 {
                    idct_dequant_full_2x(
                        &mut q[q_off..q_off + 32],
                        dq,
                        &mut dst[dst_off..],
                        stride,
                    );
                } else if ea != 0 || eb != 0 {
                    idct_dequant_0_2x(
                        &mut q[q_off..q_off + 32],
                        dq[0],
                        &mut dst[dst_off..],
                        stride,
                    );
                }
            }
        }
    }
}

/// Driver for the 8 chroma blocks (U then V, each a 2x2 grid of blocks).
pub(crate) fn vp8_dequant_idct_add_uv_block_neon(
    q: &mut [i16; 128],
    dq: &[i16; 16],
    dst_u: &mut [u8],
    dst_v: &mut [u8],
    stride: usize,
    eobs: &[i8; 8],
) {
    for plane in 0..2 {
        let dst = if plane == 0 { &mut *dst_u } else { &mut *dst_v };
        for row in 0..2 {
            let blk = plane * 4 + row * 2;
            let (ea, eb) = (eobs[blk], eobs[blk + 1]);
            let dst_off = row * 4 * stride;
            let q_off = blk * 16;
            // SAFETY: NEON baseline on aarch64.
            unsafe {
                if ea > 1 || eb > 1 {
                    idct_dequant_full_2x(
                        &mut q[q_off..q_off + 32],
                        dq,
                        &mut dst[dst_off..],
                        stride,
                    );
                } else if ea != 0 || eb != 0 {
                    idct_dequant_0_2x(
                        &mut q[q_off..q_off + 32],
                        dq[0],
                        &mut dst[dst_off..],
                        stride,
                    );
                }
            }
        }
    }
}

// ===========================================================================
// NEON-specific sixtap sub-pixel filter. Not generic: it auto-vectorizes well
// in scalar (~1.13x), below the bar to port to other ISAs, so it stays NEON-only
// and isn't part of the `Simd` trait. Bit-exact with filter_block2d_sixtap_safe.
// ===========================================================================

/// The sub-pel filter index 0 is the identity `[0, 0, 128, 0, 0, 0]`: with the
/// `+64 >> 7` rounding it maps every 0..=255 input to itself exactly. So when a
/// filter is the identity, that pass is a pure copy and can be skipped without
/// changing a single output bit. libvpx specializes the same way.
#[inline(always)]
fn is_identity(f: &[i16; 6]) -> bool {
    f[0] == 0 && f[1] == 0 && f[3] == 0 && f[4] == 0 && f[5] == 0
}

pub(crate) fn filter_block2d_sixtap_neon(
    src: &[u8],
    src_stride: usize,
    dst: &mut [u8],
    dst_pitch: usize,
    width: usize,
    height: usize,
    h_filter: &[i16; 6],
    v_filter: &[i16; 6],
) {
    let ih = height + 5;
    let last_base = (width.div_ceil(8) - 1) * 8;
    let req_src = ih.saturating_sub(1) * src_stride + last_base + 13;
    let req_dst = height.saturating_sub(1) * dst_pitch + width;
    if src.len() < req_src || dst.len() < req_dst || width == 0 || height == 0 {
        crate::vp8::common::filter::filter_block2d_sixtap_safe(
            src, src_stride, dst, dst_pitch, width, height, h_filter, v_filter,
        );
        return;
    }
    let h_id = is_identity(h_filter);
    let v_id = is_identity(v_filter);
    // SAFETY: NEON baseline; the length checks above keep every load/store in
    // bounds of `src`, `dst`, and the padded `mid`. The fast paths read a strict
    // subset of what the bounds check above guarantees (`req_src` is the full
    // two-pass extent).
    unsafe {
        match (h_id, v_id) {
            // Both identity: integer-pel, pure copy from the (+2,+2) center tap.
            (true, true) => sixtap_copy(src, src_stride, dst, dst_pitch, width, height),
            // Horizontal identity: vertical 6-tap straight from src (col +2).
            (true, false) => {
                sixtap_v_only(src, src_stride, dst, dst_pitch, width, height, v_filter)
            }
            // Vertical identity: horizontal 6-tap straight to dst (row +2).
            (false, true) => {
                sixtap_h_only(src, src_stride, dst, dst_pitch, width, height, h_filter)
            }
            // Both fractional: fused two-pass (horizontal results kept in a
            // 6-row register window, no i16 intermediate buffer).
            (false, false) => {
                sixtap_impl(
                    src, src_stride, dst, dst_pitch, width, height, h_filter, v_filter,
                );
            }
        }
    }
}

/// Absolute values of a sub-pel filter's 6 taps. Every VP8 sub-pel filter has
/// the fixed sign pattern `+,-,+,+,-,+` (taps 1 and 4 non-positive, the rest
/// non-negative), so the MAC below hard-codes which taps add vs subtract.
#[inline(always)]
fn abs_filter6(f: &[i16; 6]) -> [u8; 6] {
    let mut a = [0u8; 6];
    for k in 0..6 {
        a[k] = f[k].unsigned_abs() as u8;
    }
    a
}

/// 6-tap MAC over 8 lanes using `u8 * u8 -> u16` widening multiplies (libvpx's
/// scheme): one multiply per tap across all 8 lanes, vs widening to i32 and
/// doing two `vmlal_s16` halves. `b[k]` holds the 8 source bytes for tap k; `af`
/// the absolute taps. Taps 0,2,3,5 add (`vmlal_u8`); taps 1,4 subtract
/// (`vmlsl_u8`). Accumulating in two groups -- each carrying one of the two
/// large taps (2 and 3) -- keeps every partial within i16 range; the groups are
/// combined with a signed saturating add and rounded/clamped to u8 with
/// `vqrshrun_n_s16`. This reproduces the scalar `clamp((64 + sum) >> 7, 0, 255)`
/// exactly: the `+64` rounding and `>> 7` are the `vqrshrun` shift, and the
/// saturating add + saturating narrow give the `0..=255` clamp.
#[target_feature(enable = "neon")]
fn sixtap_mac6(b: &[uint8x8_t; 6], af: &[u8; 6]) -> uint8x8_t {
    let mut a = vmull_u8(b[0], vdup_n_u8(af[0]));
    a = vmlsl_u8(a, b[4], vdup_n_u8(af[4]));
    a = vmlal_u8(a, b[2], vdup_n_u8(af[2]));
    let mut c = vmull_u8(b[5], vdup_n_u8(af[5]));
    c = vmlsl_u8(c, b[1], vdup_n_u8(af[1]));
    c = vmlal_u8(c, b[3], vdup_n_u8(af[3]));
    let d = vqaddq_s16(vreinterpretq_s16_u16(c), vreinterpretq_s16_u16(a));
    vqrshrun_n_s16::<7>(d)
}

/// Horizontal-only 6-tap (yoffset == 0): output row `i` is the horizontal filter
/// of src row `i + 2`. Bit-exact with the two-pass filter using an identity
/// vertical filter.
#[target_feature(enable = "neon")]
fn sixtap_h_only(
    src: &[u8],
    src_stride: usize,
    dst: &mut [u8],
    dst_pitch: usize,
    width: usize,
    height: usize,
    hf: &[i16; 6],
) {
    let af = abs_filter6(hf);
    for i in 0..height {
        let row = (i + 2) * src_stride;
        let mut c = 0;
        while c < width {
            let bytes = hfilter_strip(src, row + c, &af);
            sixtap_store_u8(&mut dst[i * dst_pitch + c..], bytes, (width - c).min(8));
            c += 8;
        }
    }
}

/// Vertical-only 6-tap (xoffset == 0): output row `i` filters src rows `i..i+5`
/// at column `+2`. Bit-exact with the two-pass filter using an identity
/// horizontal filter.
#[target_feature(enable = "neon")]
fn sixtap_v_only(
    src: &[u8],
    src_stride: usize,
    dst: &mut [u8],
    dst_pitch: usize,
    width: usize,
    height: usize,
    vf: &[i16; 6],
) {
    let af = abs_filter6(vf);
    for i in 0..height {
        let mut c = 0;
        while c < width {
            let base = i * src_stride + c + 2;
            // SAFETY: req_src bounds guarantee these 6 strided rows are in range.
            let b = unsafe {
                [
                    vld1_u8(src.as_ptr().add(base)),
                    vld1_u8(src.as_ptr().add(base + src_stride)),
                    vld1_u8(src.as_ptr().add(base + 2 * src_stride)),
                    vld1_u8(src.as_ptr().add(base + 3 * src_stride)),
                    vld1_u8(src.as_ptr().add(base + 4 * src_stride)),
                    vld1_u8(src.as_ptr().add(base + 5 * src_stride)),
                ]
            };
            let bytes = sixtap_mac6(&b, &af);
            sixtap_store_u8(&mut dst[i * dst_pitch + c..], bytes, (width - c).min(8));
            c += 8;
        }
    }
}

/// Integer-pel copy (xoffset == 0 && yoffset == 0): both passes are identities,
/// so output row `i` is src row `i + 2` shifted right by the `+2` center tap.
#[target_feature(enable = "neon")]
fn sixtap_copy(
    src: &[u8],
    src_stride: usize,
    dst: &mut [u8],
    dst_pitch: usize,
    width: usize,
    height: usize,
) {
    for i in 0..height {
        let base = (i + 2) * src_stride + 2;
        let mut c = 0;
        while c < width {
            let v = unsafe { vld1_u8(src.as_ptr().add(base + c)) };
            sixtap_store_u8(&mut dst[i * dst_pitch + c..], v, (width - c).min(8));
            c += 8;
        }
    }
}

/// Horizontal 6-tap over one 8-pixel strip at `src[base..]`, returning the
/// clamped u8 result (the predictor pixels). `af` is the absolute filter.
#[target_feature(enable = "neon")]
fn hfilter_strip(src: &[u8], base: usize, af: &[u8; 6]) -> uint8x8_t {
    // SAFETY: req_src bounds guarantee `src[base..base + 13]` is in range.
    let b = unsafe {
        [
            vld1_u8(src.as_ptr().add(base)),
            vld1_u8(src.as_ptr().add(base + 1)),
            vld1_u8(src.as_ptr().add(base + 2)),
            vld1_u8(src.as_ptr().add(base + 3)),
            vld1_u8(src.as_ptr().add(base + 4)),
            vld1_u8(src.as_ptr().add(base + 5)),
        ]
    };
    sixtap_mac6(&b, af)
}

/// Fused two-pass 6-tap (both offsets fractional). Per 8-col strip, a sliding
/// 6-row window of horizontally-filtered rows (u8) lives in registers and feeds
/// the vertical filter directly, so the intermediate never touches memory. The
/// arithmetic matches the scalar two-pass filter, so it stays bit-exact.
#[target_feature(enable = "neon")]
fn sixtap_impl(
    src: &[u8],
    src_stride: usize,
    dst: &mut [u8],
    dst_pitch: usize,
    width: usize,
    height: usize,
    hf: &[i16; 6],
    vf: &[i16; 6],
) {
    let haf = abs_filter6(hf);
    let vaf = abs_filter6(vf);
    let mut c = 0;
    while c < width {
        let n = (width - c).min(8);
        // Prime the window with horizontally-filtered rows 0..=5.
        let mut w = [
            hfilter_strip(src, c, &haf),
            hfilter_strip(src, src_stride + c, &haf),
            hfilter_strip(src, 2 * src_stride + c, &haf),
            hfilter_strip(src, 3 * src_stride + c, &haf),
            hfilter_strip(src, 4 * src_stride + c, &haf),
            hfilter_strip(src, 5 * src_stride + c, &haf),
        ];
        for i in 0..height {
            let bytes = sixtap_mac6(&w, &vaf);
            sixtap_store_u8(&mut dst[i * dst_pitch + c..], bytes, n);
            // Slide the window down one row.
            if i + 1 < height {
                w[0] = w[1];
                w[1] = w[2];
                w[2] = w[3];
                w[3] = w[4];
                w[4] = w[5];
                w[5] = hfilter_strip(src, (i + 6) * src_stride + c, &haf);
            }
        }
        c += 8;
    }
}

#[target_feature(enable = "neon")]
fn sixtap_store_u8(dst: &mut [u8], v: uint8x8_t, n: usize) {
    if n >= 8 {
        unsafe { vst1_u8(dst.as_mut_ptr(), v) };
    } else {
        let mut tmp = [0u8; 8];
        unsafe { vst1_u8(tmp.as_mut_ptr(), v) };
        dst[..n].copy_from_slice(&tmp[..n]);
    }
}

// ===========================================================================
// NEON DC-only inverse transform add (vp8_dc_only_idct_add), in place. The
// whole 4x4 transform of a DC-only block reduces to adding the single rounded
// DC term `(input_dc + 4) >> 3` to every predictor pixel and clamping to
// 0..=255. The predictor is the current `dst` content. Bit-exact with
// vp8_dc_only_idct_add_scalar: the per-row vector add in i16 followed by
// `vqmovun_s16` (unsigned saturating narrow) reproduces the scalar
// `clamp(a1 + dst, 0, 255)` exactly. `a1` fits in i16 (|input_dc| <= 32767 so
// |a1| <= ~4100) and dst is 0..=255, so the i16 add never overflows.
// ===========================================================================

pub(crate) fn vp8_dc_only_idct_add_neon(input_dc: i16, dst: &mut [u8], dst_stride: i32) {
    let a1 = ((input_dc as i32 + 4) >> 3) as i16;
    let ds = dst_stride as usize;
    // SAFETY: NEON baseline. Each row touches 4 valid dst bytes; the load reads
    // an 8-byte register but only the low 4 lanes are stored back, and callers
    // always provide >= 3*stride + 4 bytes (a full 4x4 block). The read of a row
    // completes before that row is written, so the in-place update is sound.
    unsafe {
        let dc = vdupq_n_s16(a1);
        for r in 0..4 {
            let p = vld1_u8(dst.as_ptr().add(r * ds));
            let widened = vreinterpretq_s16_u16(vmovl_u8(p));
            let sum = vaddq_s16(widened, dc);
            let bytes = vqmovun_s16(sum);
            let mut tmp = [0u8; 8];
            vst1_u8(tmp.as_mut_ptr(), bytes);
            dst[r * ds..r * ds + 4].copy_from_slice(&tmp[..4]);
        }
    }
}

#[cfg(test)]
mod tests {
    use super::*;
    use crate::vp8::common::filter::{filter_block2d_sixtap_safe, vp8_sub_pel_filters};
    use crate::vp8::common::loopfilter_filters::{
        loop_filter_horizontal_edge_scalar, loop_filter_vertical_edge_scalar,
        mbloop_filter_horizontal_edge_scalar, mbloop_filter_vertical_edge_scalar,
    };

    fn lcg(state: &mut u64) -> u8 {
        *state = state
            .wrapping_mul(6364136223846793005)
            .wrapping_add(1442695040888963407);
        (*state >> 33) as u8
    }

    #[test]
    fn neon_dequant_idct_add_y_block_matches_scalar_bit_exact() {
        use crate::vp8::common::idct_blk::vp8_dequant_idct_add_y_block_scalar;
        let stride = 24i32;
        let s = stride as usize;
        let dst_len = 15 * s + 16;
        for trial in 0..4000 {
            let mut seed = (trial as u64)
                .wrapping_mul(2862933555777941757)
                .wrapping_add(5);
            // Bounded dequantized coefficients (|q*dq| small) so no i16 butterfly
            // intermediate saturates -> the saturating NEON matches the i32
            // scalar exactly (real-stream saturation is covered by the
            // differential, matching libvpx's NEON).
            let mut q = [0i16; 256];
            let mut eobs = [0i8; 16];
            for blk in 0..16 {
                let eob = (lcg(&mut seed) % 17) as i8; // 0..=16
                eobs[blk] = eob;
                // Respect the decode invariant: only the first `eob` coefficients
                // may be nonzero (so eob<=1 means DC-only). Otherwise a DC-only
                // block paired with a full block would legitimately differ
                // (scalar uses the DC path, NEON the full path) on an input that
                // can't occur in a real stream.
                for k in 0..(eob as usize) {
                    q[blk * 16 + k] = (lcg(&mut seed) as i16) - 128; // [-128,127]
                }
            }
            let mut dq = [0i16; 16];
            for d in dq.iter_mut() {
                *d = (lcg(&mut seed) % 32) as i16 + 1; // [1,32]
            }
            let mut dst_a = vec![0u8; dst_len];
            for b in dst_a.iter_mut() {
                *b = lcg(&mut seed);
            }
            let dst_b = dst_a.clone();
            let (mut qa, mut qb) = (q, q);
            let mut a = dst_a;
            let mut b = dst_b;
            vp8_dequant_idct_add_y_block_scalar(&mut qa, &dq, &mut a, stride, &eobs);
            vp8_dequant_idct_add_y_block_neon(&mut qb, &dq, &mut b, s, &eobs);
            assert_eq!(a, b, "y_block dst trial={trial}");
        }
    }

    #[test]
    fn neon_dc_only_idct_add_matches_scalar_bit_exact() {
        use crate::vp8::common::idctllm::vp8_dc_only_idct_add_scalar;
        let dst_stride = 24i32;
        for trial in 0..20000 {
            let mut seed = (trial as u64)
                .wrapping_mul(6364136223846793005)
                .wrapping_add(13);
            // Cover the full DC range, including values that drive a1 out of
            // 0..=255 so the saturation paths are exercised.
            let input_dc = (((lcg(&mut seed) as u16) << 8) | lcg(&mut seed) as u16) as i16;
            // Identical strided predictor content in both buffers (read in place).
            let mut a = vec![0u8; 4 * dst_stride as usize];
            for r in 0..4 {
                for c in 0..4 {
                    a[r * dst_stride as usize + c] = lcg(&mut seed);
                }
            }
            let mut b = a.clone();
            vp8_dc_only_idct_add_scalar(input_dc, &mut a, dst_stride);
            vp8_dc_only_idct_add_neon(input_dc, &mut b, dst_stride);
            assert_eq!(a, b, "dc_only trial={trial} input_dc={input_dc}");
        }
    }

    fn check_sixtap(width: usize, height: usize) {
        let stride = width + 16;
        let src_len = (height + 5) * stride + 32;
        for xo in 0..8 {
            for yo in 0..8 {
                let hf = &vp8_sub_pel_filters[xo];
                let vf = &vp8_sub_pel_filters[yo];
                let mut seed = (xo * 131 + yo * 977 + width * 17 + height) as u64 + 1;
                let mut src = vec![0u8; src_len];
                for b in src.iter_mut() {
                    *b = lcg(&mut seed);
                }
                let mut a = vec![0u8; height * width];
                let mut b = vec![0u8; height * width];
                filter_block2d_sixtap_safe(&src, stride, &mut a, width, width, height, hf, vf);
                filter_block2d_sixtap_neon(&src, stride, &mut b, width, width, height, hf, vf);
                assert_eq!(a, b, "sixtap {width}x{height} xo={xo} yo={yo}");
            }
        }
    }

    #[test]
    fn neon_sixtap_matches_scalar_bit_exact() {
        check_sixtap(4, 4);
        check_sixtap(8, 4);
        check_sixtap(8, 8);
        check_sixtap(16, 16);
    }

    #[test]
    fn neon_loopfilter_matches_scalar_bit_exact() {
        let p = 32usize;
        for trial in 0..200 {
            let mut seed = trial as u64 * 2654435761 + 1;
            let blimit = vec![lcg(&mut seed) % 40 + 1; 16];
            let limit = vec![lcg(&mut seed) % 20 + 1; 16];
            let thresh = vec![lcg(&mut seed) % 16; 16];
            let mut buf = vec![0u8; 32 * p];
            for x in buf.iter_mut() {
                *x = lcg(&mut seed);
            }
            for count in 1..=2usize {
                // block edges
                let (a, b) = run2(
                    &buf,
                    6 * p + 4,
                    p,
                    &blimit,
                    &limit,
                    &thresh,
                    count,
                    loop_filter_horizontal_edge_scalar,
                    loop_filter_horizontal_edge_neon,
                );
                assert_eq!(a, b, "lf h trial={trial} count={count}");
                let (a, b) = run2(
                    &buf,
                    2 * p + 8,
                    p,
                    &blimit,
                    &limit,
                    &thresh,
                    count,
                    loop_filter_vertical_edge_scalar,
                    loop_filter_vertical_edge_neon,
                );
                assert_eq!(a, b, "lf v trial={trial} count={count}");
                // MB edges
                let (a, b) = run2(
                    &buf,
                    6 * p + 4,
                    p,
                    &blimit,
                    &limit,
                    &thresh,
                    count,
                    mbloop_filter_horizontal_edge_scalar,
                    mbloop_filter_horizontal_edge_neon,
                );
                assert_eq!(a, b, "mb h trial={trial} count={count}");
                let (a, b) = run2(
                    &buf,
                    2 * p + 8,
                    p,
                    &blimit,
                    &limit,
                    &thresh,
                    count,
                    mbloop_filter_vertical_edge_scalar,
                    mbloop_filter_vertical_edge_neon,
                );
                assert_eq!(a, b, "mb v trial={trial} count={count}");
            }
        }
    }

    #[test]
    fn neon_simple_loopfilter_matches_scalar_bit_exact() {
        use crate::vp8::common::loopfilter_filters::{
            vp8_loop_filter_simple_horizontal_edge_scalar,
            vp8_loop_filter_simple_vertical_edge_scalar,
        };
        let stride = 32usize;
        for trial in 0..200 {
            let mut seed = trial as u64 * 1099087573 + 3;
            let blimit = lcg(&mut seed) % 60 + 1;
            let mut buf = vec![0u8; 24 * stride];
            for x in buf.iter_mut() {
                *x = lcg(&mut seed);
            }
            // horizontal (off has >= 2 rows above, 16 cols)
            let mut a = buf.clone();
            let mut b = buf.clone();
            vp8_loop_filter_simple_horizontal_edge_scalar(&mut a, 6 * stride, stride, blimit);
            simple_horizontal_edge_neon(&mut b, 6 * stride, stride, blimit);
            assert_eq!(a, b, "simple h trial={trial}");
            // vertical
            let mut a = buf.clone();
            let mut b = buf.clone();
            vp8_loop_filter_simple_vertical_edge_scalar(&mut a, 2 * stride + 8, stride, blimit);
            simple_vertical_edge_neon(&mut b, 2 * stride + 8, stride, blimit);
            assert_eq!(a, b, "simple v trial={trial}");
        }
    }

    #[allow(clippy::too_many_arguments)]
    fn run2(
        buf: &[u8],
        off: usize,
        p: usize,
        bl: &[u8],
        li: &[u8],
        th: &[u8],
        count: usize,
        scalar: fn(&mut [u8], usize, usize, &[u8], &[u8], &[u8], usize),
        neon: fn(&mut [u8], usize, usize, u8, u8, u8, usize),
    ) -> (Vec<u8>, Vec<u8>) {
        let mut a = buf.to_vec();
        let mut b = buf.to_vec();
        scalar(&mut a, off, p, bl, li, th, count);
        neon(&mut b, off, p, bl[0], li[0], th[0], count);
        (a, b)
    }
}
