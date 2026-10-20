// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <ATen/MemoryOverlap.h>
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/hip/HIPException.h>
#include <torch/extension.h>

#include <algorithm>
#include <cmath>
#include <cstdint>
#include <limits>
#include <type_traits>

namespace aiter {
namespace {

// Keep the intermediate scalar_t conversion: eager materializes GELU in the
// input dtype, then promotes it back to float for the separate multiplication.
// This TU has its own JIT module so its floating-point flags do not affect the
// legacy single-rounding activation kernels.
template <typename scalar_t>
__global__ void gelu_and_mul_eager_kernel(scalar_t* __restrict__ out,
                                         const scalar_t* __restrict__ input,
                                         int64_t d)
{
    const int64_t row = blockIdx.x;
    const scalar_t* x = input + row * (2 * d);
    const scalar_t* gate = x + d;
    constexpr float alpha = M_SQRT1_2;
    for(int64_t i = threadIdx.x; i < d; i += blockDim.x)
    {
        const float xf = static_cast<float>(x[i]);
        const float g = xf * 0.5f * (1.0f + ::erf(xf * alpha));
        const scalar_t rounded = static_cast<scalar_t>(g);
        out[row * d + i] = static_cast<scalar_t>(static_cast<float>(rounded) *
                                               static_cast<float>(gate[i]));
    }
}

// Small batches need parallelism within each row. Each thread computes one
// element, so there is no row-length-dependent loop or vector alignment rule.
template <typename scalar_t, bool MatchVectorizedHalf>
__global__ void gelu_and_mul_eager_small_kernel(scalar_t* __restrict__ out,
                                               const scalar_t* __restrict__ input,
                                               int64_t d,
                                               int64_t fp32_rounding_end)
{
    const int64_t row = blockIdx.y;
    const int64_t i = static_cast<int64_t>(blockIdx.x) * blockDim.x + threadIdx.x;
    if(i >= d)
        return;
    const float xf = static_cast<float>(input[row * (2 * d) + i]);
    constexpr float alpha = M_SQRT1_2;
    scalar_t rounded;
    if constexpr(MatchVectorizedHalf)
    {
        // DTK/PyTorch's contiguous FP16 GELU materializes the FP32 product
        // in complete vectorized blocks; its tail/strided path permits the
        // mixed FP32-multiply/FP16-convert instruction. Preserve both paths.
        float left = xf * 0.5f;
        float right = 1.0f + ::erf(xf * alpha);
        if(i < fp32_rounding_end)
        {
            float g = left * right;
            asm volatile("" : "+v"(g));
            rounded = static_cast<scalar_t>(g);
        }
        else
        {
            // Keep the tail conversion in this branch. Without the bit-level
            // barrier, the compiler can hoist/sink it across the branch and
            // change rounding and signed-zero behavior. These emit no ISA.
            asm volatile("" : "+v"(left), "+v"(right));
            rounded = static_cast<scalar_t>(left * right);
            asm volatile("" : "+v"(rounded.x));
        }
    }
    else
    {
        const float g = xf * 0.5f * (1.0f + ::erf(xf * alpha));
        rounded = static_cast<scalar_t>(g);
    }
    out[row * d + i] = static_cast<scalar_t>(
        static_cast<float>(rounded) * static_cast<float>(input[row * (2 * d) + d + i]));
}

template <typename scalar_t>
void launch_gelu_and_mul_eager(torch::Tensor& out, const torch::Tensor& input,
                               int64_t d, int64_t rows, hipStream_t stream)
{
    if(rows <= 64)
    {
        constexpr int threads = 256;
        const int64_t tiles = (d + threads - 1) / threads;
        TORCH_CHECK(tiles <= std::numeric_limits<uint32_t>::max(), "input row is too wide");
        const dim3 grid(static_cast<uint32_t>(tiles), static_cast<uint32_t>(rows));
        if constexpr(std::is_same_v<scalar_t, at::Half>)
        {
            // PyTorch 2.11 ROCm: 256 threads * 8 FP16 elements per contiguous
            // block. A single row is contiguous; multi-row x slices are not.
            // The vec8 path requires eight-element (16-byte) input alignment.
            constexpr int eager_vector_block = 256 * 8;
            if(rows == 1 && d >= eager_vector_block &&
               reinterpret_cast<uintptr_t>(input.data_ptr<scalar_t>()) % 16 == 0)
            {
                gelu_and_mul_eager_small_kernel<scalar_t, true><<<grid, threads, 0, stream>>>(
                    out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(), d,
                    d / eager_vector_block * eager_vector_block);
                return;
            }
        }
        gelu_and_mul_eager_small_kernel<scalar_t, false><<<grid, threads, 0, stream>>>(
            out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(), d, 0);
        return;
    }
    const int threads = static_cast<int>(std::min<int64_t>(256, ((d + 63) / 64) * 64));
    gelu_and_mul_eager_kernel<scalar_t><<<rows, threads, 0, stream>>>(
        out.data_ptr<scalar_t>(), input.data_ptr<scalar_t>(), d);
}

} // namespace

void gelu_and_mul_eager(torch::Tensor& out, const torch::Tensor& input)
{
    TORCH_CHECK(input.is_cuda() && out.is_cuda(), "input and out must be GPU tensors");
    TORCH_CHECK(input.device() == out.device(), "input and out must be on the same device");
    TORCH_CHECK(input.scalar_type() == at::kHalf || input.scalar_type() == at::kBFloat16,
                "input must be FP16 or BF16");
    TORCH_CHECK(out.scalar_type() == input.scalar_type(), "input and out must have the same dtype");
    TORCH_CHECK(input.dim() >= 1 && input.size(-1) % 2 == 0,
                "input must have shape [..., 2 * d]");
    TORCH_CHECK(input.is_contiguous() && out.is_contiguous(), "input and out must be contiguous");
    auto expected = input.sizes().vec();
    expected.back() /= 2;
    TORCH_CHECK(out.sizes() == at::IntArrayRef(expected), "out must have shape [..., d]");
    at::assert_no_overlap(out, input);
    if(out.numel() == 0)
        return;

    const int64_t d = out.size(-1);
    const int64_t rows = out.numel() / d;
    TORCH_CHECK(rows <= std::numeric_limits<int32_t>::max(), "too many input rows");
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    AT_DISPATCH_SWITCH(input.scalar_type(), "gelu_and_mul_eager",
        AT_DISPATCH_CASE(at::ScalarType::Half, [&] {
            launch_gelu_and_mul_eager<scalar_t>(out, input, d, rows, stream);
        })
        AT_DISPATCH_CASE(at::ScalarType::BFloat16, [&] {
            launch_gelu_and_mul_eager<scalar_t>(out, input, d, rows, stream);
        }));
    C10_HIP_CHECK(hipGetLastError());
}

} // namespace aiter

PYBIND11_MODULE(TORCH_EXTENSION_NAME, m)
{
    m.def("gelu_and_mul_eager", &aiter::gelu_and_mul_eager,
          "GELU and multiply with an intermediate input-dtype rounding.",
          pybind11::arg("out"), pybind11::arg("input"));
}
