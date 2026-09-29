// SPDX-License-Identifier: MIT

#pragma once

#include <torch/torch.h>

#include <optional>
#include <vector>

#include "aiter_common.h"

namespace aiter {
namespace native {

// LibTorch C++ entry matching the public vLLM-aligned Python HIP API.
AITER_CPP_TORCH_API std::vector<torch::Tensor>
chunk_gated_delta_rule_fwd(
    const torch::Tensor& k,
    const torch::Tensor& w,
    const torch::Tensor& u,
    const std::optional<torch::Tensor>& g = std::nullopt,
    const std::optional<torch::Tensor>& gk = std::nullopt,
    const std::optional<torch::Tensor>& initial_state = std::nullopt,
    const std::optional<torch::Tensor>& initial_state_indices = std::nullopt,
    bool output_final_state = true,
    int chunk_size = 64,
    bool save_new_value = true,
    const std::optional<torch::Tensor>& cu_seqlens = std::nullopt,
    const std::optional<torch::Tensor>& chunk_indices = std::nullopt,
    const std::optional<torch::Tensor>& chunk_offsets = std::nullopt,
    bool use_exp2 = false,
    bool transpose_state_layout = true);

AITER_CPP_TORCH_API std::vector<torch::Tensor>
chunk_gated_delta_rule_fwd_sglang(
    const torch::Tensor& k,
    const torch::Tensor& w,
    const torch::Tensor& u,
    const std::optional<torch::Tensor>& g = std::nullopt,
    const std::optional<torch::Tensor>& gk = std::nullopt,
    const std::optional<torch::Tensor>& initial_state = std::nullopt,
    const std::optional<torch::Tensor>& initial_state_indices = std::nullopt,
    bool output_final_state = true,
    int chunk_size = 64,
    bool save_new_value = true,
    const std::optional<torch::Tensor>& cu_seqlens = std::nullopt,
    const std::optional<torch::Tensor>& chunk_indices = std::nullopt,
    const std::optional<torch::Tensor>& chunk_offsets = std::nullopt,
    bool use_exp2 = false,
    bool transpose_state_layout = true);

AITER_CPP_TORCH_API std::vector<torch::Tensor>
vllm_fused_sigmoid_gating_delta_rule_update(
    const torch::Tensor& A_log,
    const torch::Tensor& a,
    const torch::Tensor& b,
    const torch::Tensor& dt_bias,
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& v,
    float beta = 1.0f,
    float threshold = 20.0f,
    const std::optional<float>& scale = std::nullopt,
    const std::optional<torch::Tensor>& initial_state = std::nullopt,
    bool inplace_final_state = true,
    const std::optional<torch::Tensor>& cu_seqlens = std::nullopt,
    const std::optional<torch::Tensor>& ssm_state_indices = std::nullopt,
    const std::optional<torch::Tensor>& num_accepted_tokens = std::nullopt,
    bool use_qk_l2norm_in_kernel = false,
    bool is_kda = false);

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
    bool use_qk_l2norm_in_kernel = false);

AITER_CPP_TORCH_API torch::Tensor
chunk_fwd_o_vllm_hip_blockdim64(
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& v,
    const torch::Tensor& h,
    const std::optional<torch::Tensor>& g = std::nullopt,
    const std::optional<torch::Tensor>& g_gamma = std::nullopt,
    double scale = 1.0,
    const std::optional<torch::Tensor>& cu_seqlens = std::nullopt,
    const std::optional<torch::Tensor>& chunk_indices = std::nullopt,
    int chunk_size = 64,
    bool use_exp2 = false,
    bool transpose_state_layout = true);

AITER_CPP_TORCH_API torch::Tensor
chunk_gated_delta_rule_fwd_kkt_solve_hip(
    const torch::Tensor& k,
    const torch::Tensor& beta,
    const std::optional<torch::Tensor>& g,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices,
    int chunk_size);

} // namespace native
} // namespace aiter
