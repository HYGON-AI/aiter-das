// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include "chunk_gated_delta_rule_fwd_kkt_solve_kernel.h"
#include "static_switch.h"

#include <cstdint>
#include <type_traits>

namespace FLA_NAMESPACE {

template <typename ScalarT, typename BetaT, typename CuIndexT, typename ChunkIndexT,
          bool UseG, bool GroupHeads, bool FullRows, bool TailMmac,
          bool SwizzleScratch>
void launch_chunk_gated_delta_rule_fwd_kkt_solve_grid(
    KktSolveParams &params, hipStream_t stream)
{
    const int launch_heads = GroupHeads ? params.Hg : params.H;
    const dim3 grid(static_cast<unsigned int>(params.NT),
                    static_cast<unsigned int>(params.B * launch_heads),
                    1);
    const dim3 block(256, 1, 1);
    constexpr size_t scratch_smem_size =
        kKktScratchWithScaleElements * sizeof(float);
    constexpr size_t rhs_smem_size = kKktRhsLdsElements * sizeof(ScalarT);
    constexpr size_t smem_size =
        scratch_smem_size > rhs_smem_size ? scratch_smem_size : rhs_smem_size;

    hipLaunchKernelGGL(
        (chunk_gated_delta_rule_fwd_kkt_solve_kernel<
            ScalarT, BetaT, CuIndexT, ChunkIndexT, UseG, GroupHeads, FullRows,
            TailMmac, SwizzleScratch>),
        grid, block, smem_size, stream, params);
}

template <typename ScalarT>
void run_chunk_gated_delta_rule_fwd_kkt_solve_typed(
    KktSolveParams &params, hipStream_t stream)
{
    BOOL_SWITCH(params.beta_is_float, BetaIsFloat, [&] {
    BOOL_SWITCH(params.cu_seqlens_i64, CuIndexIsI64, [&] {
    BOOL_SWITCH(params.chunk_indices_i64, ChunkIndexIsI64, [&] {
    BOOL_SWITCH(params.use_g, UseG, [&] {
    const bool can_mmac = params.K == kKktBK && params.BT == kKktMaxBT;
    const bool full_rows =
        can_mmac &&
        static_cast<int64_t>(params.NT) * params.BT == params.T;
    const int heads_per_k = params.H / params.Hg;
    const int64_t grouped_ctas =
        static_cast<int64_t>(params.B) * params.NT * params.Hg;
    const bool use_group_heads =
        can_mmac &&
        heads_per_k > 1 &&
        (full_rows || grouped_ctas >= 512 ||
         (heads_per_k <= 2 && grouped_ctas >= 128));
    const bool use_tail_mmac =
        can_mmac && !full_rows && params.NT >= 8;
    const bool use_swizzle_scratch =
        can_mmac && params.NT >= 64;
    BOOL_SWITCH(use_group_heads, GroupHeads, [&] {
    BOOL_SWITCH(full_rows, FullRows, [&] {
    BOOL_SWITCH(use_tail_mmac, TailMmac, [&] {
    BOOL_SWITCH(use_swizzle_scratch, SwizzleScratch, [&] {
        using BetaT = std::conditional_t<BetaIsFloat, float, ScalarT>;
        using CuIndexT = std::conditional_t<CuIndexIsI64, int64_t, int32_t>;
        using ChunkIndexT = std::conditional_t<ChunkIndexIsI64, int64_t, int32_t>;
        launch_chunk_gated_delta_rule_fwd_kkt_solve_grid<
            ScalarT, BetaT, CuIndexT, ChunkIndexT, UseG, GroupHeads, FullRows,
            TailMmac, SwizzleScratch>(
                params, stream);
    });});});});});});});});
}

}  // namespace FLA_NAMESPACE
