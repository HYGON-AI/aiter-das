// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "moe_c_activation.h"

#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <cmath>
#include <iostream>
#include <stdexcept>
#include <string>

namespace {

void require(bool ok, const std::string& message)
{
    if(!ok) throw std::runtime_error(message);
}

} // namespace

int main()
{
    require(torch::cuda::is_available(), "CUDA/HIP device is not available");
    torch::manual_seed(20260902);
    constexpr int64_t tokens = 257;
    constexpr int64_t width = 1536;
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kHalf);
    auto input = (torch::randn({tokens, width}, opts) / 4.0).contiguous();
    auto output = torch::empty_like(input);

    moe_c_activation_gelu_tanh(output, input, 1, 2);
    require(hipDeviceSynchronize() == hipSuccess, "GELU device synchronization failed");

    auto x = input.to(torch::kFloat);
    constexpr double alpha = 0.7978845608028654; // sqrt(2 / pi)
    auto reference = 0.5 * x * (1.0 + torch::tanh(alpha * (x + 0.044715 * x * x * x)));
    const double max_abs = (output.to(torch::kFloat) - reference).abs().max().item<double>();
    require(torch::allclose(output.to(torch::kFloat), reference, 1e-2, 2e-3, true),
            "moe_c_activation_gelu_tanh mismatch, max_abs=" + std::to_string(max_abs));
    require(torch::isfinite(output).all().item<bool>(), "GELU produced NaN/Inf");
    std::cout << "moe_c_activation_gelu_tanh passed max_abs=" << max_abs << "\n";
    return 0;
}
