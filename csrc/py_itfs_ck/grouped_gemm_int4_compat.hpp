// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

// Private compatibility path, included after the CK host frontend by the adapter.
// Keep it separate from FP16/BF16 selection: raw CK INT4 column-major A did not
// pass dense validation. This byte transpose preserves the public TT contract
// using the validated NT kernel, at the cost of staging and a synchronizing free.
#include <algorithm>

namespace {
__global__ void transpose_int4_a(const unsigned char* source, unsigned char* target,
                                int m, int packed_k, int source_stride)
{
    const std::size_t size = static_cast<std::size_t>(m) * packed_k;
    for(std::size_t i = static_cast<std::size_t>(blockIdx.x) * blockDim.x + threadIdx.x;
        i < size; i += static_cast<std::size_t>(gridDim.x) * blockDim.x)
        target[i] = source[(i % packed_k) * source_stride + i / packed_k];
}

int run_int4_tt(const ck_tile_hcu_grouped_gemm_desc* descs, int count,
                void* workspace, hipStream_t stream)
{
    std::size_t total = 0;
    for(int i = 0; i < count; ++i)
        total += static_cast<std::size_t>(descs[i].M) * (descs[i].K / 2);
    // The original workspace-size ABI has no shape information. Own this
    // shape-dependent staging buffer; DeviceMem keeps it alive until work ends.
    ck_tile::DeviceMem packed(total);
    auto* next = static_cast<unsigned char*>(packed.GetDeviceBuffer());
    std::vector<ck_tile_hcu_grouped_gemm_desc> normalized(descs, descs + count);
    for(auto& d : normalized)
    {
        const std::size_t size = static_cast<std::size_t>(d.M) * (d.K / 2);
        hipLaunchKernelGGL(transpose_int4_a, dim3(std::min<std::size_t>((size + 255) / 256, 65535)),
                           dim3(256), 0, stream, static_cast<const unsigned char*>(d.a_ptr),
                           next, d.M, d.K / 2, d.stride_A);
        HIP_CHECK_ERROR(hipGetLastError());
        d.a_ptr = next;
        d.stride_A = d.K / 2;
        next += size;
    }
    return aiter_ck_grouped_gemm_run_legacy(normalized.data(), count,
        CK_TILE_HCU_GROUPED_GEMM_INT4, 'R', 'C', workspace, stream);
}
} // namespace
