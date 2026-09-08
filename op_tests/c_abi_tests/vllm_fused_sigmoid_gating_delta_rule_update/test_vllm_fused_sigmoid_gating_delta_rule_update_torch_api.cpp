// SPDX-License-Identifier: MIT

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/script.h>
#include <torch/torch.h>

#include <filesystem>
#include <iostream>
#include <optional>
#include <stdexcept>
#include <string>

namespace {

constexpr double kRtol = 5e-2;
constexpr double kAtol = 5e-2;

torch::Tensor load(const torch::jit::Module& fixture, const std::string& name)
{
    return fixture.attr(name).toTensor();
}

void require(bool ok, const std::string& message)
{
    if(!ok)
    {
        throw std::runtime_error(message);
    }
}

void check_close(const char* name, const torch::Tensor& actual, const torch::Tensor& expected)
{
    auto actual_f = actual.to(torch::kFloat);
    auto expected_f = expected.to(torch::kFloat);
    if(!torch::allclose(actual_f, expected_f, kRtol, kAtol, true))
    {
        const double max_abs = (actual_f - expected_f).abs().max().item<double>();
        throw std::runtime_error(std::string("C++ API ") + name +
                                 " mismatch, max_abs=" + std::to_string(max_abs));
    }
}

void run_case(const torch::jit::Module& fixture,
              const char* prefix,
              const std::optional<torch::Tensor>& num_accepted_tokens)
{
    const auto name = [prefix](const char* suffix) {
        return std::string(prefix) + "_" + suffix;
    };

    auto initial_state = load(fixture, name("initial_state")).clone();
    auto outputs = aiter::native::vllm_fused_sigmoid_gating_delta_rule_update(
        load(fixture, name("A_log")),
        load(fixture, name("a")),
        load(fixture, name("b")),
        load(fixture, name("dt_bias")),
        load(fixture, name("q")),
        load(fixture, name("k")),
        load(fixture, name("v")),
        1.0f,
        20.0f,
        std::nullopt,
        initial_state,
        true,
        load(fixture, name("cu_seqlens")),
        load(fixture, name("ssm_state_indices")),
        num_accepted_tokens,
        true,
        false);

    require(outputs.size() == 2, std::string(prefix) + " returned an unexpected number of tensors");
    if(hipDeviceSynchronize() != hipSuccess)
    {
        throw std::runtime_error(std::string(prefix) + " hipDeviceSynchronize failed");
    }

    check_close((std::string(prefix) + " out").c_str(),
                outputs[0],
                load(fixture, name("expected_out")));
    check_close((std::string(prefix) + " final_state").c_str(),
                outputs[1],
                load(fixture, name("expected_final_state")));
    check_close((std::string(prefix) + " inplace_state").c_str(),
                initial_state,
                load(fixture, name("expected_final_state")));
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

    run_case(fixture, "decode", std::nullopt);
    run_case(fixture, "spec", load(fixture, "spec_num_accepted_tokens"));

    std::cout << "vllm_fused_sigmoid_gating_delta_rule_update LibTorch C++ API passed\n";
    return 0;
}
