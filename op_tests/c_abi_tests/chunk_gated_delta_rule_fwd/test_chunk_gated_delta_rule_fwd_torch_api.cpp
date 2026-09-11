// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/script.h>
#include <torch/torch.h>

#include <filesystem>
#include <iostream>
#include <stdexcept>
#include <string>

namespace {

torch::Tensor load(const torch::jit::Module& fixture, const char* name)
{
    return fixture.attr(name).toTensor();
}

void check_close(const char* name, const torch::Tensor& actual, const torch::Tensor& expected)
{
    if(!torch::allclose(actual, expected, 2e-2, 2e-2, true))
    {
        const double max_abs = (actual.to(torch::kFloat) - expected.to(torch::kFloat))
                                   .abs()
                                   .max()
                                   .item<double>();
        throw std::runtime_error(std::string("C++ API ") + name +
                                 " mismatch, max_abs=" + std::to_string(max_abs));
    }
}

} // namespace

int main(int argc, char** argv)
{
    if(argc != 2)
    {
        std::cerr << "usage: " << argv[0] << " FIXTURE_DIR\n";
        return 2;
    }
    if(!torch::cuda::is_available())
    {
        std::cerr << "HIP device is not available\n";
        return 1;
    }

    const std::filesystem::path root(argv[1]);
    auto fixture = torch::jit::load((root / "fixture.pt").string(), torch::kCUDA);
    auto k = load(fixture, "k");
    auto w = load(fixture, "w");
    auto u = load(fixture, "u");
    auto g = load(fixture, "g");
    auto initial_state = load(fixture, "initial_state");
    auto initial_state_indices = load(fixture, "initial_state_indices");

    auto outputs = aiter::native::chunk_gated_delta_rule_fwd(
        k, w, u, g, std::nullopt, initial_state, initial_state_indices,
        true, 64, true, std::nullopt, std::nullopt, std::nullopt, false, true);
    if(outputs.size() != 3)
    {
        throw std::runtime_error("C++ API returned an unexpected number of tensors");
    }
    if(hipDeviceSynchronize() != hipSuccess)
    {
        throw std::runtime_error("hipDeviceSynchronize failed");
    }

    check_close("h", outputs[0], load(fixture, "expected_h"));
    check_close("v_new", outputs[1], load(fixture, "expected_v_new"));
    check_close("final_state", outputs[2], load(fixture, "expected_final_state"));
    std::cout << "chunk_gated_delta_rule_fwd LibTorch C++ API passed\n";

    auto sglang_state = load(fixture, "sglang_initial_state").clone();
    auto sglang_outputs = aiter::native::chunk_gated_delta_rule_fwd_sglang(
        k, w, u, g, std::nullopt, sglang_state, initial_state_indices,
        true, 64, true, std::nullopt, std::nullopt, std::nullopt, false, true);
    if(sglang_outputs.size() != 2)
    {
        throw std::runtime_error("SGLang C++ API returned an unexpected number of tensors");
    }
    if(hipDeviceSynchronize() != hipSuccess)
    {
        throw std::runtime_error("hipDeviceSynchronize failed");
    }

    check_close("sglang h", sglang_outputs[0], load(fixture, "expected_sglang_h"));
    check_close("sglang v_new", sglang_outputs[1], load(fixture, "expected_sglang_v_new"));
    check_close("sglang state", sglang_state, load(fixture, "expected_sglang_state"));
    std::cout << "chunk_gated_delta_rule_fwd_sglang LibTorch C++ API passed\n";
    return 0;
}
