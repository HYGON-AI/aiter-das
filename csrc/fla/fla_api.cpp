// SPDX-License-Identifier: MIT

#include "fla_api.h"

#include "fla.h"

namespace aiter {
namespace native {

AITER_CPP_TORCH_API std::vector<torch::Tensor>
chunk_gated_delta_rule_fwd(
    const torch::Tensor& k,
    const torch::Tensor& w,
    const torch::Tensor& u,
    const std::optional<torch::Tensor>& g,
    const std::optional<torch::Tensor>& gk,
    const std::optional<torch::Tensor>& initial_state,
    const std::optional<torch::Tensor>& initial_state_indices,
    bool output_final_state,
    int chunk_size,
    bool save_new_value,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices,
    const std::optional<torch::Tensor>& chunk_offsets,
    bool use_exp2,
    bool transpose_state_layout)
{
    return ::chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout);
}

AITER_CPP_TORCH_API std::vector<torch::Tensor>
chunk_gated_delta_rule_fwd_sglang(
    const torch::Tensor& k,
    const torch::Tensor& w,
    const torch::Tensor& u,
    const std::optional<torch::Tensor>& g,
    const std::optional<torch::Tensor>& gk,
    const std::optional<torch::Tensor>& initial_state,
    const std::optional<torch::Tensor>& initial_state_indices,
    bool output_final_state,
    int chunk_size,
    bool save_new_value,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices,
    const std::optional<torch::Tensor>& chunk_offsets,
    bool use_exp2,
    bool transpose_state_layout)
{
    return ::chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
        k,
        w,
        u,
        g,
        gk,
        initial_state,
        initial_state_indices,
        output_final_state,
        chunk_size,
        save_new_value,
        cu_seqlens,
        chunk_indices,
        chunk_offsets,
        use_exp2,
        transpose_state_layout);
}

AITER_CPP_TORCH_API std::vector<torch::Tensor>
vllm_fused_sigmoid_gating_delta_rule_update(
    const torch::Tensor& A_log,
    const torch::Tensor& a,
    const torch::Tensor& b,
    const torch::Tensor& dt_bias,
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& v,
    float beta,
    float threshold,
    const std::optional<float>& scale,
    const std::optional<torch::Tensor>& initial_state,
    bool inplace_final_state,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& ssm_state_indices,
    const std::optional<torch::Tensor>& num_accepted_tokens,
    bool use_qk_l2norm_in_kernel,
    bool is_kda)
{
    return ::vllm_fused_sigmoid_gating_delta_rule_update(
        A_log,
        a,
        b,
        dt_bias,
        q,
        k,
        v,
        beta,
        threshold,
        scale,
        initial_state,
        inplace_final_state,
        cu_seqlens,
        ssm_state_indices,
        num_accepted_tokens,
        use_qk_l2norm_in_kernel,
        is_kda);
}

AITER_CPP_TORCH_API std::vector<torch::Tensor>
aiter_fused_recurrent_gated_delta_rule_packed_decode(
    const torch::Tensor& mixed_qkv,
    const torch::Tensor& a,
    const torch::Tensor& b,
    const torch::Tensor& A_log,
    const torch::Tensor& dt_bias,
    float scale,
    const torch::Tensor& initial_state,
    const torch::Tensor& out,
    const torch::Tensor& ssm_state_indices,
    bool use_qk_l2norm_in_kernel)
{
    return ::aiter_fused_recurrent_gated_delta_rule_packed_decode(
        mixed_qkv,
        a,
        b,
        A_log,
        dt_bias,
        scale,
        initial_state,
        out,
        ssm_state_indices,
        use_qk_l2norm_in_kernel);
}

AITER_CPP_TORCH_API torch::Tensor
chunk_fwd_o_vllm_hip_blockdim64(
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& v,
    const torch::Tensor& h,
    const std::optional<torch::Tensor>& g,
    const std::optional<torch::Tensor>& g_gamma,
    double scale,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices,
    int chunk_size,
    bool use_exp2,
    bool transpose_state_layout)
{
    return ::chunk_fwd_o_vllm_hip_blockdim64(
        q,
        k,
        v,
        h,
        g,
        g_gamma,
        scale,
        cu_seqlens,
        chunk_indices,
        chunk_size,
        use_exp2,
        transpose_state_layout);
}

AITER_CPP_TORCH_API torch::Tensor
chunk_gated_delta_rule_fwd_kkt_solve_hip(
    const torch::Tensor& k,
    const torch::Tensor& beta,
    const std::optional<torch::Tensor>& g,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices,
    int chunk_size)
{
    return ::chunk_gated_delta_rule_fwd_kkt_solve_hip(
        k,
        beta,
        g,
        cu_seqlens,
        chunk_indices,
        chunk_size);
}

} // namespace native
} // namespace aiter
