// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include <cstdint>

// HYGON: trimmed port of the upstream header. Only the pieces the e8m0 block
// scale path of rmsnorm_quant_kernels.cu actually uses are carried over:
// the two enums, the FP8 dtype configs, fp_f32_to_e8m0_scale and
// mx_scale_shuffle_idx. Dropped upstream members and why:
//   * MxDtypeConfig<FP4_E2M1> / fp4_f32_to_e8m0_scale -- no e2m1 HW support on
//     gfx936/gfx938/gfx946, every fp4 path is compiled out.
//   * E8m0BlockScale / fp_f32_to_e8m0_block_scale -- no caller in this fork.
//   * fp4_scale_shuffle_idx -- backward-compat alias with no caller here.
// The enum *values* are kept 1:1 with upstream so a later port (L4 KV-cache
// fp4) can add the missing specializations without renumbering.

namespace aiter {

// E8M0 block-scale rounding modes for the whole MX format family
// (mxfp4 / mxfp6 / mxfp8 / mxint8) -- the four formulas FLOOR / RCEIL /
// CEIL / EVEN are dtype-agnostic, only max_pos / max_pow2 constants differ
// (see PyTorch torchao ScaleCalculationMode for the same design).
//
// Names follow upstream Quark RoundMode. Each value is 1:1 mathematically
// equivalent to a PyTorch torchao ScaleCalculationMode:
//   RoundDown <-> FLOOR, RoundUp <-> RCEIL, Even <-> EVEN, Ceil <-> CEIL.
enum class MxScaleRoundMode : int {
    RoundDown = 0, // scale = floor_pow2(amax) / 2^target_max_pow2.
                   //   ~37% max clipping (FP4 default).
    RoundUp   = 1, // scale = ceil_pow2(amax / max_pos).
                   //   0% max clipping. (industry default)
    Even      = 2, // floor_pow2(round_pow2_special(amax)) / 2^target_max_pow2.
                   //   upstream Quark default for MXFP4/MXFP8.
    Ceil      = 3, // scale = ceil_pow2(amax) / 2^target_max_pow2.
                   //   0% max clipping but coarser grid than RoundUp.
};

constexpr MxScaleRoundMode kDefaultMxScaleRoundMode = MxScaleRoundMode::RoundUp;

// MX-format element dtype tag selecting per-dtype constants.
//
// Note that FP8_E4M3 (a.k.a. e4m3fn) and FP8_E4M3_FNUZ are **different
// formats** with different max_pos (448 vs 240) and different
// target_max_pow2 (8 vs 7); they are NOT interchangeable.
//   * FP8_E4M3      = OCP / upstream gfx950+ / **HCU gfx938, gfx946**.
//                     exp_bias = 7, max_normal = 448.
//                     Matches opus::finfo<fp8_t>::max() on this fork and the
//                     448 divisor the per-token e8m0 path in
//                     csrc/kernels/quant_kernels.cu already uses.
//   * FP8_E4M3_FNUZ = upstream gfx942 hardware FP8 (MI300 family).
//                     exp_bias = 8, max_normal = 240. No HCU target has it.
enum class MxDtype : int {
    FP4_E2M1      = 0, // no MxDtypeConfig here: fp4 is compiled out on HCU
    FP8_E4M3      = 1, // max_pos = 448.0,  target_max_pow2 = 8,  mbits = 3
    FP8_E4M3_FNUZ = 2, // max_pos = 240.0,  target_max_pow2 = 7,  mbits = 3
};

// Per-MX-dtype constants. The four scale rounding formulas depend on:
//   * max_pos        : max representable normal value of the target dtype
//                      (used by RoundUp / RCEIL: ceil_pow2(amax / max_pos)).
//   * target_max_pow2: log2(largest pow2 <= max_pos)
//                      (used by RoundDown / Ceil / Even: divisor
//                      2^target_max_pow2).
//   * mbits          : mantissa bits of the target dtype
//                      (used by Even: val_to_add = 1 << (23 - mbits - 1)).
template <MxDtype dtype> struct MxDtypeConfig;

template <> struct MxDtypeConfig<MxDtype::FP8_E4M3> {
    static constexpr int      target_max_pow2 = 8;              // log2(256), 256 <= 448
    static constexpr float    max_pos         = 448.0f;
    static constexpr float    inv_max_pos     = 1.0f / 448.0f;  // 0x3B124925
    static constexpr float    inv_max_pow2    = 1.0f / 256.0f;  // 1/256 = 0x3B800000
    static constexpr int      mbits           = 3;
    static constexpr uint32_t even_val_to_add = 0x00080000u;    // 1 << (23 - 3 - 1) = 1 << 19
};

// upstream gfx942 hardware FP8 (e4m3fnuz): exp_bias = 8 (one bigger than the
// OCP e4m3fn = 7), so max_normal = 240.0 (= 1.875 * 2^7) and the largest
// pow-2 fitting under it is 128 = 2^7. Mantissa width is the same 3 bits,
// so the EVEN val_to_add is identical to FP8_E4M3.
template <> struct MxDtypeConfig<MxDtype::FP8_E4M3_FNUZ> {
    static constexpr int      target_max_pow2 = 7;              // log2(128), 128 <= 240
    static constexpr float    max_pos         = 240.0f;
    static constexpr float    inv_max_pos     = 1.0f / 240.0f;  // 0x3B888889
    static constexpr float    inv_max_pow2    = 1.0f / 128.0f;  // 1/128 = 0x3C000000
    static constexpr int      mbits           = 3;
    static constexpr uint32_t even_val_to_add = 0x00080000u;    // 1 << (23 - 3 - 1) = 1 << 19
};

// Generic E8M0 dequant scale computation.
//
// Returns the *dequantization* scale as an f32 with a power-of-2 bit pattern,
// ready for direct multiplication into the dequantized data and for E8M0 bit
// extraction via (__float_as_uint(s) >> 23) & 0xFF.
//
// The template parameters are compile-time constants, so the if constexpr
// branch is fully resolved before codegen -- no runtime dispatch overhead.
//
// NaN/Inf inputs preserve the f32 exponent (0xFF) which downstream consumers
// interpret as E8M0 NaN.
template <MxScaleRoundMode rmode = kDefaultMxScaleRoundMode,
          MxDtype          dtype = MxDtype::FP8_E4M3>
__device__ __forceinline__ float fp_f32_to_e8m0_scale(float amax)
{
    using Cfg = MxDtypeConfig<dtype>;

    if constexpr(rmode == MxScaleRoundMode::RoundUp)
    {
        // ceil_pow2(amax / max_pos): NV / DSv4 / FlashInfer / torchao RCEIL.
        const uint32_t u32      = __builtin_bit_cast(uint32_t, amax * Cfg::inv_max_pos);
        uint32_t       exponent = (u32 >> 23) & 0xFFu;
        if(exponent < 0xFFu && (u32 & 0x7FFFFFu))
            exponent += 1;
        return __builtin_bit_cast(float, exponent << 23);
    }
    else if constexpr(rmode == MxScaleRoundMode::RoundDown)
    {
        // floor_pow2(amax) / 2^target_max_pow2: OCP MX / torchao FLOOR.
        const uint32_t u32      = __builtin_bit_cast(uint32_t, amax * Cfg::inv_max_pow2);
        const uint32_t exponent = (u32 >> 23) & 0xFFu;
        return __builtin_bit_cast(float, exponent << 23);
    }
    else if constexpr(rmode == MxScaleRoundMode::Ceil)
    {
        // ceil_pow2(amax) / 2^target_max_pow2: torchao CEIL.
        const uint32_t u32      = __builtin_bit_cast(uint32_t, amax * Cfg::inv_max_pow2);
        uint32_t       exponent = (u32 >> 23) & 0xFFu;
        if(exponent < 0xFFu && (u32 & 0x7FFFFFu))
            exponent += 1;
        return __builtin_bit_cast(float, exponent << 23);
    }
    else if constexpr(rmode == MxScaleRoundMode::Even)
    {
        // floor_pow2(round_pow2_special(amax)) / 2^target_max_pow2:
        // Quark EVEN / torchao EVEN. Add a half-step at the (mbits+1)-th-from-
        // top mantissa bit, drop the mantissa, then subtract target_max_pow2
        // from the biased exponent (saturating to >= 0). NaN/Inf input
        // preserves exponent 0xFF.
        const uint32_t bits     = __builtin_bit_cast(uint32_t, amax);
        const uint32_t rounded  = (bits + Cfg::even_val_to_add) & 0xFF800000u;
        const uint32_t raw_exp  = (rounded >> 23) & 0xFFu;
        const uint32_t exponent = (raw_exp >= static_cast<uint32_t>(Cfg::target_max_pow2))
                                      ? (raw_exp - static_cast<uint32_t>(Cfg::target_max_pow2))
                                      : 0u;
        return __builtin_bit_cast(float, exponent << 23);
    }
}

// Compute the swizzled E8M0 scale index for the tiled MX layout. Used by both
// MXFP4 and MXFP8 paths (the e8m0 byte layout is identical regardless of the
// element dtype).
__device__ __forceinline__ int mx_scale_shuffle_idx(int scaleN_pad, int x, int y)
{
    return (x / 32 * scaleN_pad) * 32 + (y / 8) * 256 + (y % 4) * 64 + (x % 16) * 4 +
           (y % 8) / 4 * 2 + (x % 32) / 16;
}

} // namespace aiter
