// Copyright (c) 2024, Advanced Micro Devices, Inc. All rights reserved.
#pragma once
// SPDX-License-Identifier: MIT
 
#include <torch/torch.h>
#include <optional>
#include "aiter_common.h"

// 从 module_cpp_api.so 导出的公开 libtorch C++ 入口。
// Python pybind 绑定同一函数，kernel 实现保持在模块内单例。
namespace aiter {
namespace native {

// IDs outside [0, num_experts) are skipped without changing valid route weights/ranks.
// num_valid_ids counts padded entries. The metadata tensor contains E local counts
// (masked experts have zero count), then E exclusive padded offsets in global order.
// Tensors must be contiguous, on one GPU, with int32 IDs/metadata and FP32 weights.
// local_expert_mask is a length-E int32 0/1 mask, not a global-to-local expert map.
// The call is asynchronous on the current stream. Optional moe_buf is zero-filled
// and must have a 16-byte aligned address/byte size. Empty token batches are supported.
AITER_CPP_TORCH_API void moe_sorting_fwd(torch::Tensor &topk_ids,              // [m, topk]
                     torch::Tensor &topk_weights,          // [m, topk]
                     torch::Tensor &sorted_token_ids,      // [max_num_tokens_padded]
                     torch::Tensor &sorted_weights,        // [max_num_tokens_padded]
                     torch::Tensor &sorted_expert_ids,     // [max_num_m_blocks]
                     torch::Tensor &tokens_positions_per_expert,     // [num_experts*2]
                     torch::Tensor &num_valid_ids,         // [1]
                     std::optional<torch::Tensor> moe_buf = std::nullopt,  // [max_num_tokens_padded], set to None to skip zero-fill
                     int num_experts = 0,
                     int unit_size = 0,
                     std::optional<torch::Tensor> local_expert_mask = std::nullopt);

AITER_CPP_TORCH_API void moe_sorting_ck_ids_to_moe_c(
                     torch::Tensor &ck_sorted_token_ids,    // [max_num_tokens_padded]
                     torch::Tensor &moe_c_sorted_token_ids, // [max_num_tokens_padded]
                     int64_t num_tokens,
                     int64_t topk);

} // namespace native
} // namespace aiter
