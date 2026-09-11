// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <iostream>
#include <stdexcept>
#include <string>
#include <vector>

namespace {

struct DTypeCase
{
    const char* name;
    at::ScalarType dtype;
};

const std::vector<DTypeCase> kDTypes = {
    {"fp16", at::kHalf},
    {"bf16", at::kBFloat16},
};

void require(bool ok, const std::string& message)
{
    if(!ok)
    {
        throw std::runtime_error(message);
    }
}

torch::Tensor make_input(const std::vector<int64_t>& shape, at::ScalarType dtype)
{
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat);
    return (torch::randn(shape, opts) * 2.0).clamp(-7.0, 7.0).to(dtype).contiguous();
}

void run_case(const DTypeCase& dtype_case, const std::vector<int64_t>& shape)
{
    auto input = make_input(shape, dtype_case.dtype);
    auto output = torch::empty(input.sizes(),
                               torch::TensorOptions()
                                   .device(torch::kCUDA)
                                   .dtype(c10::ScalarType::Float8_e4m3fn));
    std::vector<int64_t> scale_shape = shape;
    scale_shape.back() = 1;
    auto scales = torch::empty(scale_shape,
                               torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));

    aiter::native::dynamic_per_token_scaled_quant(output, input, scales);
    require(hipDeviceSynchronize() == hipSuccess, "hipDeviceSynchronize failed");

    auto input_f = input.to(torch::kFloat);
    auto ref_scales = input_f.abs().amax(-1, true) / 448.0;
    if(!torch::allclose(scales, ref_scales, 1e-6, 1e-8, true))
    {
        const double max_abs = (scales - ref_scales).abs().max().item<double>();
        throw std::runtime_error(std::string("scale mismatch for ") + dtype_case.name +
                                 ", max_abs=" + std::to_string(max_abs));
    }

    auto ref_output = (input_f / ref_scales).to(c10::ScalarType::Float8_e4m3fn);
    auto max_abs = (output.to(torch::kFloat) - ref_output.to(torch::kFloat))
                       .abs()
                       .max()
                       .item<float>();
    require(max_abs == 0.0f,
            std::string("fp8 output mismatch for ") + dtype_case.name +
                ", max_abs=" + std::to_string(max_abs));

    std::cout << "passed quant dtype=" << dtype_case.name
              << " shape=" << input.sizes() << " max_abs=" << max_abs << "\n";
}

} // namespace

int main()
{
    if(!torch::cuda::is_available())
    {
        std::cerr << "CUDA/HIP device is not available\n";
        return 1;
    }

    torch::manual_seed(20260701);
    for(const auto& dtype_case : kDTypes)
    {
        run_case(dtype_case, {32, 7168});
        run_case(dtype_case, {2, 4, 7168});
    }
    std::cout << "all libtorch quant tests passed\n";
    return 0;
}
