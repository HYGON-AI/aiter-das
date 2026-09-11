// SPDX-License-Identifier: MIT
// Copyright (C) 2025-2026, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>

#include "opus_gemm.h"
#include "hcu/opus_gemm_pipeline_a16w16_hcu.cuh"
#include "gfx938/opus_gemm_pipeline_a8w8_gfx938.cuh"

#include <cstring>
#include <stdexcept>
#include <string>

namespace {

void require(bool condition, const std::string& message)
{
    if(!condition)
        throw std::runtime_error("opus_gemm: " + message);
}

enum class RuntimeHcuArch
{
    Unsupported,
    Gfx936,
    Gfx938,
    Gfx946,
};

RuntimeHcuArch runtime_hcu_arch()
{
    // Match upstream Opus' process-stable architecture model: query HIP once,
    // then keep the hot operator path to a static read and comparison.
    static const RuntimeHcuArch arch = [] {
        int device = 0;
        if(hipGetDevice(&device) != hipSuccess)
            return RuntimeHcuArch::Unsupported;
        hipDeviceProp_t prop{};
        if(hipGetDeviceProperties(&prop, device) != hipSuccess)
            return RuntimeHcuArch::Unsupported;
        if(std::strncmp(prop.gcnArchName, "gfx936", 6) == 0)
            return RuntimeHcuArch::Gfx936;
        if(std::strncmp(prop.gcnArchName, "gfx938", 6) == 0)
            return RuntimeHcuArch::Gfx938;
        if(std::strncmp(prop.gcnArchName, "gfx946", 6) == 0)
            return RuntimeHcuArch::Gfx946;
        return RuntimeHcuArch::Unsupported;
    }();
    return arch;
}

bool runtime_is_supported_hcu_arch()
{
    const auto arch = runtime_hcu_arch();
    return arch == RuntimeHcuArch::Gfx936 || arch == RuntimeHcuArch::Gfx938 ||
           arch == RuntimeHcuArch::Gfx946;
}

bool runtime_supports_fp8()
{
    const auto arch = runtime_hcu_arch();
    return arch == RuntimeHcuArch::Gfx938 || arch == RuntimeHcuArch::Gfx946;
}

} // namespace

void opus_gemm_a16w16_hcu(torch::Tensor& XQ,
                          torch::Tensor& WQ,
                          torch::Tensor& Y,
                          torch::Tensor& Bias,
                          torch::Tensor& Workspace,
                          int split_k,
                          int kernel_id)
{
    require(runtime_is_supported_hcu_arch(), "only gfx936, gfx938 and gfx946 are supported");
    require(XQ.is_cuda() && WQ.is_cuda() && Y.is_cuda(), "all tensors must be on a GPU");
    require(XQ.device() == WQ.device() && XQ.device() == Y.device(),
            "all tensors must be on the same GPU");
    require(XQ.dim() == 3 && WQ.dim() == 3 && Y.dim() == 3,
            "XQ, WQ and Y must be normalized to 3D");
    require(XQ.scalar_type() == at::ScalarType::BFloat16 &&
                WQ.scalar_type() == at::ScalarType::BFloat16,
            "XQ and WQ must be BF16");
    require(Y.scalar_type() == at::ScalarType::BFloat16 ||
                Y.scalar_type() == at::ScalarType::Float,
            "Y must be BF16 or FP32");
    require(XQ.is_contiguous() && WQ.is_contiguous() && Y.is_contiguous(),
            "XQ, WQ and Y must be contiguous");
    require(kernel_id >= 0 && kernel_id <= 3,
            "kernelId must be 0 (direct), 1 (LDS 16x16), 2 (LDS 32x32), "
            "or 3 (Opus 64x64x32 pipeline)");
    require(split_k >= 1, "splitK must be positive");

    const int64_t batch = XQ.size(0);
    const int64_t m = XQ.size(1);
    const int64_t k = XQ.size(2);
    const int64_t b_batch = WQ.size(0);
    const int64_t n = WQ.size(1);
    require(batch > 0 && m > 0 && n > 0 && k > 0, "zero-sized dimensions are not supported");
    require(b_batch == 1 || b_batch == batch, "WQ batch must be one or equal XQ batch");
    require(WQ.size(2) == k, "XQ and WQ K dimensions must match");
    require(Y.size(0) == batch && Y.size(1) == m && Y.size(2) == n,
            "Y shape must be [batch, M, N]");
    require(split_k <= (k + 15) / 16,
            "splitK cannot exceed the number of 16-element K tiles");
    if(kernel_id == 3)
    {
        require(m % 64 == 0 && n % 64 == 0,
                "kernelId 3 requires M and N divisible by 64");
        require(k % 32 == 0,
                "kernelId 3 requires K divisible by 32");
        require(split_k <= k / 32,
                "kernelId 3 splitK cannot exceed the number of 32-element K tiles");
    }

    const bool has_bias = Bias.numel() != 0;
    int bias_stride_batch = -1;
    if(has_bias)
    {
        require(Bias.is_cuda() && Bias.device() == XQ.device(),
                "bias must be on the same GPU as XQ");
        require(Bias.is_contiguous(), "bias must be contiguous");
        require(Bias.scalar_type() == at::ScalarType::BFloat16 ||
                    Bias.scalar_type() == at::ScalarType::Float,
                "bias must be BF16 or FP32");
        if(Bias.dim() == 1)
        {
            require(Bias.size(0) == n, "1D bias shape must be [N]");
            bias_stride_batch = 0;
        }
        else
        {
            require(Bias.dim() == 2 && Bias.size(0) == batch && Bias.size(1) == n,
                    "2D bias shape must be [batch, N]");
            bias_stride_batch = static_cast<int>(Bias.stride(0));
        }
    }

    if(split_k > 1)
    {
        require(Workspace.is_cuda() && Workspace.device() == XQ.device(),
                "splitK workspace must be on the same GPU as XQ");
        require(Workspace.scalar_type() == at::ScalarType::Float && Workspace.is_contiguous(),
                "splitK workspace must be contiguous FP32");
        require(Workspace.dim() == 4 && Workspace.size(0) == split_k &&
                    Workspace.size(1) == batch && Workspace.size(2) == m &&
                    Workspace.size(3) == n,
                "splitK workspace shape must be [splitK, batch, M, N]");
    }

    const long long stride_a_batch = XQ.stride(0);
    const long long stride_b_batch = b_batch == 1 ? 0 : WQ.stride(0);
    const long long stride_c_batch = Y.stride(0);
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(XQ));
    if(kernel_id == 3)
    {
        hipLaunchKernelGGL(opus_gemm_a16w16_hcu_opus_64x64x32_kernel,
                           dim3(n / 64, m / 64, batch * split_k),
                           dim3(256),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(),
                           WQ.data_ptr(),
                           Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           split_k > 1 ? Workspace.data_ptr<float>() : nullptr,
                           static_cast<int>(batch),
                           static_cast<int>(m),
                           static_cast<int>(n),
                           static_cast<int>(k),
                           stride_a_batch,
                           stride_b_batch,
                           stride_c_batch,
                           split_k,
                           bias_stride_batch,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    else if(kernel_id == 2)
    {
        hipLaunchKernelGGL(opus_gemm_a16w16_hcu_lds_32x32_kernel,
                           dim3((n + 31) / 32, (m + 31) / 32, batch * split_k),
                           dim3(256),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(),
                           WQ.data_ptr(),
                           Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           split_k > 1 ? Workspace.data_ptr<float>() : nullptr,
                           static_cast<int>(batch),
                           static_cast<int>(m),
                           static_cast<int>(n),
                           static_cast<int>(k),
                           stride_a_batch,
                           stride_b_batch,
                           stride_c_batch,
                           split_k,
                           bias_stride_batch,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    else if(kernel_id == 1)
    {
        hipLaunchKernelGGL(opus_gemm_a16w16_hcu_lds_kernel,
                           dim3((n + 15) / 16, (m + 15) / 16, batch * split_k),
                           dim3(64),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(),
                           WQ.data_ptr(),
                           Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           split_k > 1 ? Workspace.data_ptr<float>() : nullptr,
                           static_cast<int>(batch),
                           static_cast<int>(m),
                           static_cast<int>(n),
                           static_cast<int>(k),
                           stride_a_batch,
                           stride_b_batch,
                           stride_c_batch,
                           split_k,
                           bias_stride_batch,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    else
    {
        hipLaunchKernelGGL(opus_gemm_a16w16_hcu_kernel,
                           dim3((n + 15) / 16, (m + 15) / 16, batch * split_k),
                           dim3(64),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(),
                           WQ.data_ptr(),
                           Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           split_k > 1 ? Workspace.data_ptr<float>() : nullptr,
                           static_cast<int>(batch),
                           static_cast<int>(m),
                           static_cast<int>(n),
                           static_cast<int>(k),
                           stride_a_batch,
                           stride_b_batch,
                           stride_c_batch,
                           split_k,
                           bias_stride_batch,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    hipError_t status = hipGetLastError();
    require(status == hipSuccess,
            std::string("kernel launch failed: ") + hipGetErrorString(status));

    if(split_k > 1)
    {
        const long long output_elements = batch * m * n;
        const dim3 reduce_grid((output_elements + 255) / 256);
        hipLaunchKernelGGL(opus_gemm_a16w16_splitk_reduce_hcu_kernel,
                           reduce_grid,
                           dim3(256),
                           0,
                           at::hip::getCurrentHIPStream(),
                           Workspace.data_ptr<float>(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           Y.data_ptr(),
                           static_cast<int>(batch),
                           static_cast<int>(m),
                           static_cast<int>(n),
                           split_k,
                           stride_c_batch,
                           bias_stride_batch,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
        status = hipGetLastError();
        require(status == hipSuccess,
                std::string("splitK reduce launch failed: ") + hipGetErrorString(status));
    }
}

void opus_gemm_a8w8_gfx938(torch::Tensor& XQ,
                           torch::Tensor& WQ,
                           torch::Tensor& Y,
                           torch::Tensor& Bias,
                           float scale_ab,
                           int kernel_id)
{
    require(runtime_supports_fp8(), "FP8 path only supports gfx938 and gfx946");
    require(XQ.is_cuda() && WQ.is_cuda() && Y.is_cuda(), "all tensors must be on a GPU");
    require(XQ.device() == WQ.device() && XQ.device() == Y.device(),
            "all tensors must be on the same GPU");
    require(XQ.dim() == 3 && WQ.dim() == 3 && Y.dim() == 3,
            "XQ, WQ and Y must be normalized to 3D");
    require(XQ.scalar_type() == at::ScalarType::Float8_e4m3fn &&
                WQ.scalar_type() == at::ScalarType::Float8_e4m3fn,
            "XQ and WQ must be Float8_e4m3fn");
    require(Y.scalar_type() == at::ScalarType::BFloat16 ||
                Y.scalar_type() == at::ScalarType::Float,
            "Y must be BF16 or FP32");
    require(XQ.is_contiguous() && WQ.is_contiguous() && Y.is_contiguous(),
            "XQ, WQ and Y must be contiguous");
    require(kernel_id >= 0 && kernel_id <= 2,
            "FP8 kernelId must be 0 (direct), 1 (LDS 32x32), or "
            "2 (Opus 64x64x64 pipeline)");

    const int64_t batch = XQ.size(0);
    const int64_t m = XQ.size(1);
    const int64_t k = XQ.size(2);
    const int64_t b_batch = WQ.size(0);
    const int64_t n = WQ.size(1);
    require(batch > 0 && m > 0 && n > 0 && k > 0, "zero-sized dimensions are not supported");
    require(b_batch == 1 || b_batch == batch, "WQ batch must be one or equal XQ batch");
    require(WQ.size(2) == k, "XQ and WQ K dimensions must match");
    require(Y.size(0) == batch && Y.size(1) == m && Y.size(2) == n,
            "Y shape must be [batch, M, N]");
    if(kernel_id == 2)
    {
        require(m % 64 == 0 && n % 64 == 0,
                "FP8 kernelId 2 requires M and N divisible by 64");
        require(k % 64 == 0,
                "FP8 kernelId 2 requires K divisible by 64");
    }

    const bool has_bias = Bias.numel() != 0;
    int bias_stride_batch = -1;
    if(has_bias)
    {
        require(Bias.is_cuda() && Bias.device() == XQ.device(),
                "bias must be on the same GPU as XQ");
        require(Bias.is_contiguous(), "bias must be contiguous");
        require(Bias.scalar_type() == at::ScalarType::BFloat16 ||
                    Bias.scalar_type() == at::ScalarType::Float,
                "bias must be BF16 or FP32");
        if(Bias.dim() == 1)
        {
            require(Bias.size(0) == n, "1D bias shape must be [N]");
            bias_stride_batch = 0;
        }
        else
        {
            require(Bias.dim() == 2 && Bias.size(0) == batch && Bias.size(1) == n,
                    "2D bias shape must be [batch, N]");
            bias_stride_batch = static_cast<int>(Bias.stride(0));
        }
    }

    const long long stride_a_batch = XQ.stride(0);
    const long long stride_b_batch = b_batch == 1 ? 0 : WQ.stride(0);
    const long long stride_c_batch = Y.stride(0);
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(XQ));
    if(kernel_id == 2)
    {
        hipLaunchKernelGGL(opus_gemm_a8w8_gfx938_opus_64x64x64_kernel,
                           dim3(n / 64, m / 64, batch),
                           dim3(256),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(), WQ.data_ptr(), Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           static_cast<int>(batch), static_cast<int>(m),
                           static_cast<int>(n), static_cast<int>(k),
                           stride_a_batch, stride_b_batch, stride_c_batch,
                           bias_stride_batch, scale_ab,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    else if(kernel_id == 1)
    {
        hipLaunchKernelGGL(opus_gemm_a8w8_gfx938_lds_32x32_kernel,
                           dim3((n + 31) / 32, (m + 31) / 32, batch),
                           dim3(256),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(), WQ.data_ptr(), Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           static_cast<int>(batch), static_cast<int>(m),
                           static_cast<int>(n), static_cast<int>(k),
                           stride_a_batch, stride_b_batch, stride_c_batch,
                           bias_stride_batch, scale_ab,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    else
    {
        hipLaunchKernelGGL(opus_gemm_a8w8_gfx938_kernel,
                           dim3((n + 15) / 16, (m + 15) / 16, batch),
                           dim3(64),
                           0,
                           at::hip::getCurrentHIPStream(),
                           XQ.data_ptr(), WQ.data_ptr(), Y.data_ptr(),
                           has_bias ? Bias.data_ptr() : nullptr,
                           static_cast<int>(batch), static_cast<int>(m),
                           static_cast<int>(n), static_cast<int>(k),
                           stride_a_batch, stride_b_batch, stride_c_batch,
                           bias_stride_batch, scale_ab,
                           has_bias && Bias.scalar_type() == at::ScalarType::Float,
                           Y.scalar_type() == at::ScalarType::Float);
    }
    const hipError_t status = hipGetLastError();
    require(status == hipSuccess,
            std::string("FP8 kernel launch failed: ") + hipGetErrorString(status));
}
