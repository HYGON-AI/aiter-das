// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "moe_asm.h"

#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <iostream>
#include <optional>
#include <stdexcept>
#include <string>

namespace {

void require(bool ok, const std::string& message)
{
    if(!ok) throw std::runtime_error(message);
}

torch::Tensor shuffle_stage1_weight(const torch::Tensor& weight)
{
    constexpr int64_t inner_n = 16;
    constexpr int64_t inner_k = 8;
    constexpr int64_t block_n = 64;
    constexpr int64_t block_k = 128;
    const int64_t n = weight.size(1);
    const int64_t k = weight.size(2);
    return weight
        .view({-1, n / block_n, block_n / 64, 64 / inner_n, inner_n,
               k / block_k, block_k / 32, 32 / inner_k, inner_k})
        .permute({0, 1, 5, 2, 6, 3, 7, 4, 8})
        .contiguous()
        .view(weight.sizes());
}

torch::Tensor shuffle_stage2_weight(const torch::Tensor& weight)
{
    constexpr int64_t inner_n = 16;
    constexpr int64_t inner_k = 8;
    constexpr int64_t block_n = 64;
    constexpr int64_t block_k = 32;
    const int64_t n = weight.size(1);
    const int64_t k = weight.size(2);
    return weight
        .view({-1, n / block_n, block_n / 64, 64 / inner_n, inner_n,
               k / block_k, block_k / 32, 32 / inner_k, inner_k})
        .permute({0, 1, 5, 2, 6, 3, 7, 4, 8})
        .contiguous()
        .view(weight.sizes());
}

} // namespace

int main()
{
    require(torch::cuda::is_available(), "CUDA/HIP device is not available");
    torch::manual_seed(20260902);
    constexpr int64_t tokens = 16;
    constexpr int64_t hidden = 128;
    constexpr int64_t intermediate = 64;
    constexpr int64_t experts = 1;
    constexpr int64_t topk = 1;
    constexpr int64_t block_size = 16;
    constexpr int64_t max_padded = tokens * topk + experts * block_size - topk;
    constexpr int64_t max_blocks = (max_padded + block_size - 1) / block_size;

    auto half_opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kHalf);
    auto int_opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32);
    auto float_opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat);
    auto input = (torch::randn({tokens, hidden}, half_opts) / 8.0).contiguous();
    auto logical_weight = (torch::randn({experts, intermediate, hidden}, half_opts) / 8.0).contiguous();
    auto shuffled_weight = shuffle_stage1_weight(logical_weight);
    auto output = torch::empty({tokens * topk, intermediate}, half_opts);

    const int32_t padded_id = static_cast<int32_t>((topk << 24) | tokens);
    auto sorted_ids = torch::full({max_padded}, padded_id, int_opts);
    sorted_ids.slice(0, 0, tokens).copy_(torch::arange(tokens, int_opts));
    auto sorted_weights = torch::zeros({max_padded}, float_opts);
    sorted_weights.slice(0, 0, tokens).fill_(1.0);
    auto sorted_experts = torch::full({max_blocks}, -1, int_opts);
    sorted_experts[0] = 0;
    auto num_valid_ids = torch::full({1}, tokens, int_opts);
    std::optional<torch::Tensor> no_tensor = std::nullopt;

    asm_fmoe_a8(output, input, shuffled_weight, shuffled_weight,
                 sorted_ids, sorted_weights, sorted_experts, num_valid_ids,
                 topk, no_tensor, no_tensor, no_tensor,
                 20, 10000, 0, 0, 1);
    require(hipDeviceSynchronize() == hipSuccess, "ASM MoE device synchronization failed");

    auto reference = torch::matmul(input.to(torch::kFloat),
                                   logical_weight[0].to(torch::kFloat).transpose(0, 1));
    const double max_abs = (output.to(torch::kFloat) - reference).abs().max().item<double>();
    require(torch::allclose(output.to(torch::kFloat), reference, 2e-2, 5e-2, true),
            "asm_fmoe_a8 shuffle stage1 mismatch, max_abs=" + std::to_string(max_abs));
    require(torch::isfinite(output).all().item<bool>(), "ASM MoE produced NaN/Inf");
    std::cout << "asm_fmoe_a8 W16A16 shuffle stage1 passed max_abs=" << max_abs << "\n";

    auto logical_down_weight =
        (torch::randn({experts, hidden, intermediate}, half_opts) / 8.0).contiguous();
    auto shuffled_down_weight = shuffle_stage2_weight(logical_down_weight);
    auto down_output = torch::empty({tokens * topk, hidden}, half_opts);
    asm_fmoe_a8(down_output, output, shuffled_down_weight, shuffled_down_weight,
                 sorted_ids, sorted_weights, sorted_experts, num_valid_ids,
                 topk, no_tensor, no_tensor, no_tensor,
                 21, 20000, 0, 0, 1);
    require(hipDeviceSynchronize() == hipSuccess,
            "ASM MoE stage2 device synchronization failed");

    auto down_reference = torch::matmul(output.to(torch::kFloat),
                                        logical_down_weight[0].to(torch::kFloat).transpose(0, 1));
    const double down_max_abs =
        (down_output.to(torch::kFloat) - down_reference).abs().max().item<double>();
    require(torch::allclose(down_output.to(torch::kFloat), down_reference, 2e-2, 5e-2, true),
            "asm_fmoe_a8 shuffle stage2 mismatch, max_abs=" + std::to_string(down_max_abs));
    require(torch::isfinite(down_output).all().item<bool>(), "ASM MoE stage2 produced NaN/Inf");
    std::cout << "asm_fmoe_a8 W16A16 shuffle stage2 passed max_abs=" << down_max_abs << "\n";
    return 0;
}
