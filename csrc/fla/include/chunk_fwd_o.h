// SPDX-License-Identifier: MIT
#pragma once

#include "fla.h"

namespace FLA_NAMESPACE {

struct ChunkFwdOParams
{
    using index_t = int64_t;

    void *__restrict__ q_ptr;
    void *__restrict__ k_ptr;
    void *__restrict__ v_ptr;
    void *__restrict__ h_ptr;
    void *__restrict__ g_ptr;
    void *__restrict__ g_gamma_ptr;
    void *__restrict__ o_ptr;

    index_t q_batch_stride;
    index_t q_row_stride;
    index_t q_head_stride;
    index_t k_batch_stride;
    index_t k_row_stride;
    index_t k_head_stride;
    index_t v_batch_stride;
    index_t v_row_stride;
    index_t v_head_stride;
    index_t h_batch_stride;
    index_t h_chunk_stride;
    index_t h_head_stride;
    index_t o_batch_stride;
    index_t o_row_stride;
    index_t o_head_stride;
    index_t g_batch_stride;
    index_t g_row_stride;

    int B;
    int T;
    int H;
    int Hg;
    int K;
    int V;
    int BT;
    int NT;
    int N;
    int grid_y;
    int chunk_start;
    float scale;

    void *__restrict__ cu_seqlens;
    int *__restrict__ chunk_offsets;
    void *__restrict__ chunk_indices;
    bool cu_seqlens_i64;
    bool chunk_indices_i64;
    bool use_chunk_offsets;

    bool use_g;
    bool use_g_gamma;
    bool is_varlen;
    bool is_bf16;
    bool use_chunk_indices;
    bool use_exp2;
    bool transpose_state_layout;
};

template <typename T, int kHeadDimK, int kHeadDimV>
void run_chunk_fwd_o_(
    ChunkFwdOParams &params, hipStream_t stream, bool use_safe_exp);

}  // namespace FLA_NAMESPACE
