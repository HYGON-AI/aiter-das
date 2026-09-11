// Copyright (c) 2024, Advanced Micro Devices, Inc. All rights reserved.
#pragma once
// SPDX-License-Identifier: MIT

#include <torch/extension.h>

#include <optional>

namespace aiter {

void silu_and_mul(torch::Tensor &out, torch::Tensor &input);
void scaled_silu_and_mul(torch::Tensor &out, torch::Tensor &input, torch::Tensor &scale);
void gelu_and_mul(torch::Tensor &out, torch::Tensor &input);
void gelu_tanh_and_mul(torch::Tensor &out, torch::Tensor &input);
void swiglu_variant(torch::Tensor &out, torch::Tensor &input, float alpha,
                    float limit, int mode, int rows_per_block = 1,
                    int vec_size = 2);

// Fused silu(x_gate) * y + per-token dynamic quant, ported from lightop.
void fuse_silu_mul_quant(torch::Tensor &out,             // [..., d] int8
                         torch::Tensor &input,           // [..., 2 * d]
                         torch::Tensor &scales,          // [..., 1] fp32
                         std::optional<torch::Tensor> num_local_tokens_tensor, // int32[1]
                         int64_t topk,                   // tokens multiplier for num_local_tokens
                         int64_t expect_m,               // -1: auto grid, >0: grid = expect_m * topk
                         std::optional<torch::Tensor> expert_ids); // int32, -1 tokens are skipped
void fuse_silu_mul_fp8_quant(torch::Tensor &out,         // [..., d] fp8 e4m3/e5m2
                             torch::Tensor &input,
                             torch::Tensor &scales,
                             int64_t fp8type,            // 0 = e4m3, 1 = e5m2
                             std::optional<torch::Tensor> num_local_tokens_tensor,
                             int64_t topk,
                             int64_t expect_m,
                             std::optional<torch::Tensor> expert_ids);
// EP variants on [E, T, H] layout with per-expert valid token masks.
void fuse_silu_mul_quant_ep(torch::Tensor &out,          // [E, T, d] int8
                            torch::Tensor &input,        // [E, T, 2 * d]
                            torch::Tensor &scales,       // [E, T, 1] fp32
                            std::optional<torch::Tensor> tokens_per_expert, // int32[E]
                            std::optional<torch::Tensor> num_local_tokens_tensor, // reserved
                            int64_t topk,                                        // reserved
                            int64_t expect_m);                                   // reserved
void fuse_silu_mul_fp8_quant_ep(torch::Tensor &out,      // [E, T, d] fp8
                                torch::Tensor &input,
                                torch::Tensor &scales,
                                int64_t fp8type,
                                std::optional<torch::Tensor> tokens_per_expert,
                                std::optional<torch::Tensor> num_local_tokens_tensor, // reserved
                                int64_t topk,                                         // reserved
                                int64_t expect_m);                                    // reserved
// Masked (non-quant) EP activation.
void fuse_silu_and_mul_ep(torch::Tensor &out,   // [E, T, d]
                          torch::Tensor &input, // [E, T, 2 * d]
                          const torch::Tensor &mask_m, // int32[E]
                          int64_t expect_m);
// out = relu(x)^2
void relu2(torch::Tensor &out, torch::Tensor &input);

} // namespace aiter
