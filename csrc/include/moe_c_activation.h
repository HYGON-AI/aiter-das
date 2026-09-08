// SPDX-License-Identifier: MIT
#pragma once

#include <torch/extension.h>
#include "aiter_common.h"

// Fused MoE activation kernels. input is contiguous [..., 2N] laid out as
// [gate, up] on the last dimension; out is contiguous [..., N].

void moe_c_activation_silu_and_mul(torch::Tensor& out,
                                   torch::Tensor& input,
                                   int64_t rows_per_block,
                                   int64_t vec_size);

void moe_c_activation_gelu_and_mul(torch::Tensor& out,
                                   torch::Tensor& input,
                                   int64_t rows_per_block,
                                   int64_t vec_size);

void moe_c_activation_gelu_tanh_and_mul(torch::Tensor& out,
                                        torch::Tensor& input,
                                        int64_t rows_per_block,
                                        int64_t vec_size);

void moe_c_activation_gelu(torch::Tensor& out,
                           torch::Tensor& input,
                           int64_t rows_per_block,
                           int64_t vec_size);

AITER_CPP_TORCH_API void moe_c_activation_gelu_tanh(torch::Tensor& out,
                                                    torch::Tensor& input,
                                                    int64_t rows_per_block,
                                                    int64_t vec_size);

void moe_c_activation_situ_glu(torch::Tensor& out,
                               torch::Tensor& input,
                               double beta1,
                               double beta2,
                               int64_t rows_per_block,
                               int64_t vec_size);
