// SPDX-License-Identifier: MIT
#pragma once

#include "chunk_fwd_o_kernel.h"
#include "static_switch.h"

namespace FLA_NAMESPACE {

static inline int ceildiv(const int a, const int b)
{
    return (a + b - 1) / b;
}

template <typename Element, bool UseSafeExp, bool IsVarlen,
          bool UseChunkIndices, bool SingleSeqVarlen, bool FullChunk>
void launch_chunk_fwd_o_grid(ChunkFwdOParams &params, const dim3 grid,
                             const dim3 block, const size_t smem_size,
                             hipStream_t stream)
{
    BOOL_SWITCH(params.use_g, UseG, [&] {
    BOOL_SWITCH(params.use_g_gamma, UseGGamma, [&] {
    BOOL_SWITCH(params.use_exp2, UseExp2, [&] {
        hipLaunchKernelGGL(
            (chunk_fwd_o_demo_kernel<Element, UseG, UseGGamma, UseExp2,
                                     IsVarlen, UseChunkIndices,
                                     SingleSeqVarlen, UseSafeExp, FullChunk>),
            grid, block, smem_size, stream, params);
    });});});
}

template <typename Element, bool UseSafeExp>
void launch_chunk_fwd_o_demo(ChunkFwdOParams &params, hipStream_t stream)
{
    constexpr int BT = 64;
    constexpr int BK = 128;
    constexpr int BV = 64;
    constexpr int RHS_STAGE_K = 64;
    constexpr int RHS_STAGE_COUNT = BK / RHS_STAGE_K;
    constexpr size_t smem_size =
        RHS_STAGE_COUNT * RHS_STAGE_K * BV * sizeof(Element);

    dim3 block(256, 1, 1);
    auto make_grid = [&](const ChunkFwdOParams &launch_params) {
        return dim3(ceildiv(launch_params.V, BV), launch_params.grid_y,
                    launch_params.use_chunk_indices
                        ? launch_params.H
                        : launch_params.N * launch_params.H);
    };

    if (!params.is_varlen && !params.use_chunk_indices) {
        const int full_chunks = params.T / BT;
        const int tail_tokens = params.T - full_chunks * BT;
        if (full_chunks > 0) {
            ChunkFwdOParams full_params = params;
            full_params.chunk_start = 0;
            full_params.grid_y = full_chunks;
            launch_chunk_fwd_o_grid<Element, UseSafeExp, false, false, false,
                                    true>(
                full_params, make_grid(full_params), block, smem_size, stream);
        }
        if (tail_tokens != 0) {
            ChunkFwdOParams tail_params = params;
            tail_params.chunk_start = full_chunks;
            tail_params.grid_y = 1;
            launch_chunk_fwd_o_grid<Element, UseSafeExp, false, false, false,
                                    false>(
                tail_params, make_grid(tail_params), block, smem_size, stream);
        }
        return;
    }

    if (params.is_varlen && !params.use_chunk_indices && params.N == 1) {
        const bool storage_covers_full_chunks =
            params.T >= params.grid_y * BT;
        const int full_chunks = storage_covers_full_chunks
            ? params.grid_y
            : (params.grid_y > 0 ? params.grid_y - 1 : 0);
        if (full_chunks > 0) {
            ChunkFwdOParams full_params = params;
            full_params.chunk_start = 0;
            full_params.grid_y = full_chunks;
            launch_chunk_fwd_o_grid<Element, UseSafeExp, false, false, false,
                                    true>(
                full_params, make_grid(full_params), block, smem_size, stream);
        }
        if (params.grid_y > full_chunks) {
            ChunkFwdOParams tail_params = params;
            tail_params.chunk_start = full_chunks;
            tail_params.grid_y = 1;
            launch_chunk_fwd_o_grid<Element, UseSafeExp, true, false, true,
                                    false>(
                tail_params, make_grid(tail_params), block, smem_size, stream);
        }
        return;
    }

    BOOL_SWITCH(params.is_varlen, IsVarlen, [&] {
    BOOL_SWITCH(params.use_chunk_indices, UseChunkIndices, [&] {
        params.chunk_start = 0;
        launch_chunk_fwd_o_grid<Element, UseSafeExp, IsVarlen, UseChunkIndices,
                                false, false>(
            params, make_grid(params), block, smem_size, stream);
    });});
}

template <typename T>
void run_chunk_fwd_o_k128_v128(
    ChunkFwdOParams &params, hipStream_t stream, bool use_safe_exp)
{
    TORCH_CHECK(params.transpose_state_layout,
                "chunk_fwd_o demo kernel currently supports transpose_state_layout=true only");
    BOOL_SWITCH(use_safe_exp, UseSafeExp, [&] {
        launch_chunk_fwd_o_demo<T, UseSafeExp>(params, stream);
    });
}

}  // namespace FLA_NAMESPACE
