// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "norm.h"

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

void run_case(at::ScalarType dtype)
{
    constexpr int64_t rows = 37;
    constexpr int64_t cols = 768;
    constexpr double epsilon = 1e-5;
    auto fp_opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat);
    auto input = (torch::randn({rows, cols}, fp_opts) / 4.0).to(dtype).contiguous();
    auto weight = (1.0 + torch::randn({cols}, fp_opts) / 16.0).to(dtype).contiguous();
    auto bias = (torch::randn({cols}, fp_opts) / 16.0).to(dtype).contiguous();
    auto output = torch::empty_like(input);
    std::optional<torch::Tensor> no_x_bias = std::nullopt;

    layernorm2d_out(output, input, weight, bias, epsilon, no_x_bias);
    require(hipDeviceSynchronize() == hipSuccess, "layernorm device synchronization failed");

    auto x = input.to(torch::kFloat);
    auto mean = x.mean(-1, true);
    auto variance = (x - mean).pow(2).mean(-1, true);
    auto reference = (x - mean) * torch::rsqrt(variance + epsilon);
    reference = reference * weight.to(torch::kFloat) + bias.to(torch::kFloat);
    const double max_abs = (output.to(torch::kFloat) - reference).abs().max().item<double>();
    require(torch::allclose(output.to(torch::kFloat), reference, 2e-2, 2e-2, true),
            "layernorm2d_out mismatch, max_abs=" + std::to_string(max_abs));
    std::cout << "layernorm2d_out passed dtype=" << dtype << " max_abs=" << max_abs << "\n";
}

} // namespace

int main()
{
    require(torch::cuda::is_available(), "CUDA/HIP device is not available");
    torch::manual_seed(20260902);
    run_case(torch::kHalf);
    run_case(torch::kBFloat16);
    return 0;
}
