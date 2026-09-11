// SPDX-License-Identifier: MIT
#pragma once

#include "fla.h"
#include "utils.h"

#include <type_traits>

namespace FLA_NAMESPACE {

////////////////////////////////////////////////////////////////////////////////////////////////////
// chunk_gated_delta_rule_fwd_traits
//
// Compile-time configuration bundle consumed by the kernel template.
// Encodes element / accumulator types, tile sizes (BT/BK/BV), warp layout,
// LDS partitioning, and the dispatch-flag set.
////////////////////////////////////////////////////////////////////////////////////////////////////
template <
    int  kHeadDimK_,
    int  kHeadDimV_,
    int  kBlockT_,
    int  kBlockK_,
    int  kBlockV_,
    int  kNWarps_,
    bool Use_G_,
    bool Use_GK_,
    bool Use_initial_state_,
    bool Store_final_state_,
    bool Save_new_value_,
    ExpMode Exp_mode_,
    bool Transpose_state_,
    bool Is_varlen_,
    typename VarlenIndexT_ = int32_t,
    typename elem_type = ck_tile::fp16_t,
    typename state_type = float,
    typename accm_type = ck_tile::fp32_t>
struct chunk_gated_delta_rule_fwd_traits
{
    using Element      = elem_type;
    using State        = state_type;
    using ElementAccum = accm_type;
    using index_t      = int64_t;
    using VarlenIndexT = VarlenIndexT_;

    static_assert(std::is_same_v<State, float> ||
                      std::is_same_v<State, ck_tile::bf16_t>,
                  "state type must be float or bf16");

    // --- dispatch flags (compile-time) ---
    constexpr static bool Use_G                     = Use_G_;
    constexpr static bool Use_GK                    = Use_GK_;
    constexpr static bool Use_initial_state         = Use_initial_state_;
    constexpr static bool Store_final_state         = Store_final_state_;
    constexpr static bool Save_new_value            = Save_new_value_;
    constexpr static ExpMode Exp_mode                = Exp_mode_;
    constexpr static bool Use_exp2                  = Exp_mode == ExpMode::Exp2;
    constexpr static bool Use_safe_exp              = Exp_mode == ExpMode::SafeNatural;
    constexpr static bool Transpose_state           = Transpose_state_;
    constexpr static bool Is_varlen                 = Is_varlen_;

    // --- head dims ---
    constexpr static int kHeadDimK = kHeadDimK_;
    constexpr static int kHeadDimV = kHeadDimV_;
    static_assert(kHeadDimK % 32 == 0, "kHeadDimK must be a multiple of 32");
    static_assert(kHeadDimV % 32 == 0, "kHeadDimV must be a multiple of 32");

    // --- tile sizes ---
    constexpr static int kBlockT = kBlockT_;
    constexpr static int kBlockK = kBlockK_;
    constexpr static int kBlockV = kBlockV_;
    static_assert(kBlockT == 32 || kBlockT == 64, "kBlockT must be either 32 or 64");

    // --- warp layout ---
    constexpr static int kNWarps  = kNWarps_;
    constexpr static int kThreads = kNWarps * 64;

    // --- LDS partitioning ---
    // The gfx938 BV64/BV128 paths keep authoritative FP32 state in VGPRs
    // and alias W with the chunk-local U/V image:
    //
    //   [ 0 KiB, 16 KiB): W current, then U/V
    //   [16 KiB, 32 KiB): K current
    //
    // This exact 32-KiB footprint is what permits two 256-thread CTAs to
    // reside on a 64-KiB CU.  BV16/BV32 retain their established layouts.
    constexpr static bool kAliasWUV = kBlockV == 64 || kBlockV == 128;
    constexpr static int kMicroBlockV = kAliasWUV ? 32 : kBlockV;
    constexpr static int kVTileStride = kMicroBlockV == 16 ? 32 : kMicroBlockV;
    constexpr static int kHLowStride = kBlockK;
    constexpr static int h_state_smem_size = 0;
    constexpr static int v_tile_smem_size = kAliasWUV
        ? 0
        : kBlockT * kVTileStride * sizeof(Element);
    constexpr static int h_low_smem_size = kAliasWUV
        ? 0
        : kMicroBlockV * kHLowStride * sizeof(Element);
    // BV32 reads W from GMEM; the other variants stage W in LDS.
    constexpr static int w_smem_size =
        kBlockV == 32 ? 0 : kBlockT * kBlockK * sizeof(Element);
    constexpr static int k_k_tile_smem_size =
        kBlockT * kBlockK * sizeof(Element);
    constexpr static int kKTileCount = 1;
    constexpr static int k_smem_size =
        kKTileCount * k_k_tile_smem_size;
    constexpr static int projection_smem_size = 0;

    constexpr static int smem_size =
        v_tile_smem_size + h_low_smem_size + w_smem_size + k_smem_size +
        projection_smem_size;
    static_assert(smem_size <= 65535, "smem size must be <= 64KB");
    static_assert(!kAliasWUV || smem_size == 32 * 1024,
                  "BV64/BV128 require exactly 32 KiB of LDS");

    // Compiler allocation hint for the two-CTA residency target. Actual
    // occupancy also depends on the final register allocation and hardware.
    constexpr static int kMinBlocksPerCU = kAliasWUV ? 2 : 1;

    // --- per-warp work distribution for GemmA (w @ h) ---
    constexpr static int kShapeOuterW = kBlockT / kNWarps;  // e.g. 64 / 4 = 16
    constexpr static int kShapeInnerW = kBlockK;
};

}  // namespace FLA_NAMESPACE
