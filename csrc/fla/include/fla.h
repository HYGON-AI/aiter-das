// SPDX-License-Identifier: MIT
#pragma once

#include <torch/extension.h>
#include <cstdint>
#include <optional>
#include <vector>

#include "aiter_hip_common.h"   // pulls in <hip/hip_runtime.h> + ck_tile::{fp16_t, bf16_t, fp32_t}

namespace FLA_NAMESPACE {

// The three exponent policies reachable from the public frontends.  Keeping
// this as one compile-time axis avoids materializing the invalid
// (use_safe_exp=true, use_exp2=true) cross-product.
enum class ExpMode : uint8_t
{
    Natural,
    Exp2,
    SafeNatural,
};

////////////////////////////////////////////////////////////////////////////////////////////////////
// Delta_rule_params
//
// All device-visible state for one launch of chunk_gated_delta_rule_fwd.
// Strides are in *elements* (not bytes). Pointers are raw void* so the same
// struct serves both fp16 and bf16 specializations.
////////////////////////////////////////////////////////////////////////////////////////////////////
struct Delta_rule_params
{
    using index_t = int64_t;

    // --- input tensors ---
    // k: (B, T, Hg, K)  or  (total_k, Hg, K) when varlen
    void *__restrict__ k_ptr;
    // w: (B, T, H, K)
    void *__restrict__ w_ptr;
    // u: (B, T, H, V)  --- acts as the value tensor
    void *__restrict__ u_ptr;

    // strides (in elements) for k
    index_t k_batch_stride;
    index_t k_row_stride;
    index_t k_head_stride;

    // strides for w
    index_t w_batch_stride;
    index_t w_row_stride;
    index_t w_head_stride;

    // strides for u
    index_t u_batch_stride;
    index_t u_row_stride;
    index_t u_head_stride;

    // --- optional gating tensors ---
    // g:  (B, T, H)  or  nullptr
    void *__restrict__ g_ptr;
    index_t g_batch_stride;
    index_t g_row_stride;

    // gk: (B, T, H, K)  or  nullptr
    void *__restrict__ gk_ptr;
    index_t gk_batch_stride;
    index_t gk_row_stride;
    index_t gk_head_stride;

    // --- output tensors ---
    // h: (B, NT, H, V, K) or (B, NT, H, K, V) depending on transpose_state_layout
    void *__restrict__ h_ptr;
    index_t h_batch_stride;
    index_t h_chunk_stride;
    index_t h_head_stride;

    // v_new: (B, T, H, V)  or  nullptr when !save_new_value
    void *__restrict__ v_new_ptr;
    index_t v_new_batch_stride;
    index_t v_new_row_stride;
    index_t v_new_head_stride;

    // --- initial / final state ---
    // initial_state: (state_rows, H, V, K) in the supported layout, or nullptr
    void *__restrict__ h0_ptr;
    index_t h0_batch_stride;
    index_t h0_head_stride;

    // final_state: same shape as initial_state, or nullptr
    void *__restrict__ ht_ptr;
    index_t ht_batch_stride;
    index_t ht_head_stride;

    // initial_state_indices: (N,)  or  nullptr
    const int *__restrict__ initial_state_indices;

    // --- dimensions ---
    int B;            // batch size
    int T;            // max sequence length
    int H;            // number of (query) heads
    int Hg;           // number of key heads (Hg <= H for GQA)
    int K;            // key dimension
    int V;            // value dimension
    int BT;           // chunk size (block size along T)
    int NT;           // number of chunks
    int N;            // number of sequences (B for padded, len(cu_seqlens)-1 for varlen)
    int state_rows;   // number of rows in initial/final state

    // --- varlen support ---
    // cu_seqlens: IndexT (int32/int64; see index_is_int64)
    // chunk_offsets: always int64 (SGLang cumsum promotion)
    // chunk_indices is host-only (NT); not stored here.
    void *__restrict__ cu_seqlens;     // (B+1,) device pointer, or nullptr
    void *__restrict__ chunk_offsets;  // (N,)   device pointer, or nullptr

    // --- flags ---
    bool is_varlen;
    bool index_is_int64;  // cu_seqlens element type; false => int32
    bool is_bf16;     // true => bf16, false => fp16
    bool use_g;
    bool use_gk;
    bool use_initial_state;
    bool use_initial_state_indices;
    bool store_final_state;
    bool save_new_value;
    bool use_exp2;
    bool transpose_state_layout;
};

////////////////////////////////////////////////////////////////////////////////////////////////////
// Heavy instance entry points.  Definitions live in the flat
// csrc/fla/instances/ directory, one TU per (input dtype, state dtype, BV), so
// each TU emits only its assigned kernel variants.
////////////////////////////////////////////////////////////////////////////////////////////////////
void run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv16(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv32(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv16(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv32(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv16(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv32(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv16(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv32(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
// gfx938-only logical-BV64 instances. The host selector keeps unsupported
// architectures and flag combinations on the established BV16/BV32 paths.
void run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv64(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv64(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv64(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv64(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);

// gfx938 BV128 instances, selected by auto on the tuned 72-CU target or
// explicitly with AITER_FLA_FORCE_BV=128 on supported gfx938 devices.
void run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv128(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv128(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv128(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);
void run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv128(
    Delta_rule_params &params, hipStream_t stream, ExpMode exp_mode);

////////////////////////////////////////////////////////////////////////////////////////////////////
// KktSolveParams
//
// Device-visible state for the standalone fused KKT + lower-triangular solve.
// Strides are implicit because the aiter/SGLang integration requires contiguous
// k/beta/g tensors before launch.
////////////////////////////////////////////////////////////////////////////////////////////////////
struct KktSolveParams
{
    void *__restrict__ k_ptr;              // (B, T, Hg, K)
    void *__restrict__ g_ptr;              // (B, T, H), fp32, optional
    void *__restrict__ beta_ptr;           // (B, T, H), fp32 or input dtype
    void *__restrict__ A_ptr;              // (B, T, H, BT)
    void *__restrict__ cu_seqlens;         // int32/int64, optional varlen metadata
    void *__restrict__ chunk_indices;      // int32/int64, optional varlen metadata

    int B;
    int T;
    int H;
    int Hg;
    int K;
    int BT;
    int NT;

    bool use_g;
    bool is_varlen;
    bool beta_is_float;
    bool cu_seqlens_i64;
    bool chunk_indices_i64;
};

void run_chunk_gated_delta_rule_fwd_kkt_solve_fp16(
    KktSolveParams &params, hipStream_t stream);
void run_chunk_gated_delta_rule_fwd_kkt_solve_bf16(
    KktSolveParams &params, hipStream_t stream);

}  // namespace FLA_NAMESPACE

////////////////////////////////////////////////////////////////////////////////////////////////////
// Public ABI (pybind layer sees only these declarations).
// New public names encode frontend, HIP backend, and the Triton-style blockdim64 specialization.
////////////////////////////////////////////////////////////////////////////////////////////////////
std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
    at::Tensor const &k,                                      // (B, T, Hg, K) or (total_k, Hg, K)
    at::Tensor const &w,                                      // (B, T, H, K)
    at::Tensor const &u,                                      // (B, T, H, V)
    std::optional<at::Tensor> const &g,                       // (B, T, H) or (total_k, H)
    std::optional<at::Tensor> const &gk,                      // (B, T, H, K) or (total_k, H, K)
    std::optional<at::Tensor> const &initial_state,           // (state_rows, H, V, K)
    std::optional<at::Tensor> const &initial_state_indices,   // (N,)
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,              // (B+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2); int32/int64; host NT only
    std::optional<at::Tensor> const &chunk_offsets,           // (N,) exclusive int64; required when varlen
    bool const use_exp2,
    bool const transpose_state_layout);

std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
    at::Tensor const &k,                                      // (B, T, Hg, K) or (total_k, Hg, K)
    at::Tensor const &w,                                      // (B, T, H, K)
    at::Tensor const &u,                                      // (B, T, H, V)
    std::optional<at::Tensor> const &g,                       // (B, T, H) or (total_k, H)
    std::optional<at::Tensor> const &gk,                      // (B, T, H, K) or (total_k, H, K)
    std::optional<at::Tensor> const &initial_state,           // (state_rows, H, V, K)
    std::optional<at::Tensor> const &initial_state_indices,   // (N,)
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,              // (B+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2); int32/int64; host NT only
    std::optional<at::Tensor> const &chunk_offsets,           // (N,) exclusive int64; required when varlen
    bool const use_exp2,
    bool const transpose_state_layout);

std::vector<at::Tensor>
vllm_fused_sigmoid_gating_delta_rule_update(
    at::Tensor const &A_log,
    at::Tensor const &a,
    at::Tensor const &b,
    at::Tensor const &dt_bias,
    at::Tensor const &q,
    at::Tensor const &k,
    at::Tensor const &v,
    float beta,
    float threshold,
    std::optional<float> const &scale,
    std::optional<at::Tensor> const &initial_state,
    bool inplace_final_state,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &ssm_state_indices,
    std::optional<at::Tensor> const &num_accepted_tokens,
    bool use_qk_l2norm_in_kernel,
    bool is_kda);

std::vector<at::Tensor>
aiter_fused_recurrent_gated_delta_rule_packed_decode(
    at::Tensor const &mixed_qkv,
    at::Tensor const &a,
    at::Tensor const &b,
    at::Tensor const &A_log,
    at::Tensor const &dt_bias,
    float scale,
    at::Tensor const &initial_state,
    at::Tensor const &out,
    at::Tensor const &ssm_state_indices,
    bool use_qk_l2norm_in_kernel);

// Backward-compatible aliases. Prefer the explicit *_hip_blockdim64 names in new code.
std::vector<at::Tensor>
chunk_gated_delta_rule_fwd(
    at::Tensor const &k,                                      // (B, T, Hg, K) or (total_k, Hg, K)
    at::Tensor const &w,                                      // (B, T, H, K)
    at::Tensor const &u,                                      // (B, T, H, V)
    std::optional<at::Tensor> const &g,                       // (B, T, H) or (total_k, H)
    std::optional<at::Tensor> const &gk,                      // (B, T, H, K) or (total_k, H, K)
    std::optional<at::Tensor> const &initial_state,           // (state_rows, H, V, K)
    std::optional<at::Tensor> const &initial_state_indices,   // (N,)
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,              // (B+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2); int32/int64; host NT only
    std::optional<at::Tensor> const &chunk_offsets,           // (N,) exclusive int64; required when varlen
    bool const use_exp2,
    bool const transpose_state_layout);

std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_sglang(
    at::Tensor const &k,                                      // (B, T, Hg, K) or (total_k, Hg, K)
    at::Tensor const &w,                                      // (B, T, H, K)
    at::Tensor const &u,                                      // (B, T, H, V)
    std::optional<at::Tensor> const &g,                       // (B, T, H) or (total_k, H)
    std::optional<at::Tensor> const &gk,                      // (B, T, H, K) or (total_k, H, K)
    std::optional<at::Tensor> const &initial_state,           // (state_rows, H, V, K)
    std::optional<at::Tensor> const &initial_state_indices,   // (N,)
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,              // (B+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2); int32/int64; host NT only
    std::optional<at::Tensor> const &chunk_offsets,           // (N,) exclusive int64; required when varlen
    bool const use_exp2,
    bool const transpose_state_layout);


at::Tensor
chunk_fwd_o_vllm_hip_blockdim64(
    at::Tensor const &q,                                      // (B, T, Hg, K)
    at::Tensor const &k,                                      // (B, T, Hg, K)
    at::Tensor const &v,                                      // (B, T, H, V)
    at::Tensor const &h,                                      // (B, NT, H, V, K) or (B, NT, H, K, V)
    std::optional<at::Tensor> const &g,                       // (B, T, H)
    std::optional<at::Tensor> const &g_gamma,                 // (H,)
    double const scale,
    std::optional<at::Tensor> const &cu_seqlens,              // (N+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2)
    int const chunk_size,
    bool const use_exp2,
    bool const transpose_state_layout);

at::Tensor
chunk_fwd_o_sglang_hip_blockdim64(
    at::Tensor const &q,                                      // (B, T, Hg, K)
    at::Tensor const &k,                                      // (B, T, Hg, K)
    at::Tensor const &v,                                      // (B, T, H, V)
    at::Tensor const &h,                                      // (B, NT, H, V, K)
    std::optional<at::Tensor> const &g,                       // (B, T, H)
    std::optional<at::Tensor> const &g_gamma,                 // accepted for API alignment, ignored
    double const scale,
    std::optional<at::Tensor> const &cu_seqlens,              // (N+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2)
    int const chunk_size,
    bool const use_exp2,
    bool const transpose_state_layout);

at::Tensor
chunk_gated_delta_rule_fwd_kkt_solve_hip(
    at::Tensor const &k,                                      // (B, T, Hg, K)
    at::Tensor const &beta,                                   // (B, T, H)
    std::optional<at::Tensor> const &g,                       // (B, T, H)
    std::optional<at::Tensor> const &cu_seqlens,              // (N+1,)
    std::optional<at::Tensor> const &chunk_indices,           // (NT, 2)
    int const chunk_size);
