/*
 * Copyright © Advanced Micro Devices, Inc. All rights reserved.
 
 * Copyright (c) 2024, The vLLM team.
 *
 * Licensed under the Apache License, Version 2.0 (the "License");
 * you may not use this file except in compliance with the License.
 * You may obtain a copy of the License at
 *
 *      http://www.apache.org/licenses/LICENSE-2.0
 *
 * Unless required by applicable law or agreed to in writing, software
 * distributed under the License is distributed on an "AS IS" BASIS,
 * WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
 * See the License for the specific language governing permissions and
 * limitations under the License.
 */
#include <torch/all.h>
#include <ATen/cuda/CUDAContext.h>
#include <c10/cuda/CUDAGuard.h>
#include <cuda_runtime.h>
#include <limits>
#include <ATen/MemoryOverlap.h>

// declare templates for front (cpp) and back (cuda) sides of function:
// template <typename T>

// void LLGemm_Silu(void* in_a, void* in_b, void* out_c, const int M, const int K,
//                  cudaStream_t stream, const int rows_per_block);
// void LLMM_Silu(at::Tensor& in_a, at::Tensor& in_b, at::Tensor& out_c,
//                const int64_t rows_per_block) {
//   auto M = in_a.size(0);
//   auto K = in_a.size(1);
//   LLGemm_Silu(in_a.data_ptr(), in_b.data_ptr(), out_c.data_ptr(), M, K,
//               at::cuda::getCurrentCUDAStream(), rows_per_block);
// }

void LLGemm1(void *in_a, void *in_b, void *out_c, const int M, const int K,
             cudaStream_t stream, const int rows_per_block);

// template <typename T>
void LLMM1(at::Tensor &in_a, at::Tensor &in_b, at::Tensor &out_c,
           const int64_t rows_per_block)
{
        auto M = in_a.size(0);
        auto K = in_a.size(1);
        // if (N != in_b.numel())
        //         throw std::invalid_argument("Size mismatch A.numel(): " +
        //         std::to_string(in_a.numel())
        //                           + ", B.numel(): " +
        //                           std::to_string(in_b.numel()));

        // out_c.resize_({N});

        // call the kernel function...
        const at::cuda::OptionalCUDAGuard device_guard(device_of(in_a));
        LLGemm1(in_a.data_ptr(), in_b.data_ptr(), out_c.data_ptr(), M, K,
                at::cuda::getCurrentCUDAStream(), rows_per_block);
}

void wvSpltK_(void *in_a, void *in_b, void *out_c, const int M, const int K,
              const int N, cudaStream_t stream, const int CuCount);
void wvSpltK_bf16_(void*, void*, void*, int, int, int, cudaStream_t, int);

void wvSpltK(at::Tensor &in_a, at::Tensor &in_b, at::Tensor &out_c,
             const int64_t N_in, const int64_t CuCount)
{
        TORCH_CHECK(in_a.is_cuda() && in_b.is_cuda() && out_c.is_cuda(),
                    "wvSpltK expects CUDA/HIP tensors");
        TORCH_CHECK(in_a.device() == in_b.device() && in_a.device() == out_c.device(),
                    "wvSpltK tensors must be on the same device");
        TORCH_CHECK(in_a.scalar_type() == in_b.scalar_type() &&
                    in_a.scalar_type() == out_c.scalar_type(), "wvSpltK dtypes must match");
#ifdef DTK_ENV
        TORCH_CHECK(in_a.scalar_type() == at::kHalf || in_a.scalar_type() == at::kBFloat16,
                    "wvSpltK supports float16 or bfloat16");
#else
        TORCH_CHECK(in_a.scalar_type() == at::kHalf, "wvSpltK supports float16 only on this build");
#endif
        TORCH_CHECK(in_a.dim() == 2 && in_b.dim() == 2 && out_c.dim() == 2,
                    "wvSpltK expects 2-D weight, input and output");
        TORCH_CHECK(in_a.is_contiguous() && in_b.is_contiguous() && out_c.is_contiguous(),
                    "wvSpltK expects contiguous tensors");
        TORCH_CHECK(N_in >= 1 && N_in <= 4 && N_in == in_b.size(0),
                    "wvSpltK input rows must match N_in in [1, 4]");
        TORCH_CHECK(in_a.size(1) == in_b.size(1) && out_c.size(0) == N_in &&
                    out_c.size(1) == in_a.size(0), "wvSpltK shape mismatch");
        TORCH_CHECK(in_a.size(0) > 0 && in_a.size(1) > 0 &&
                    in_a.numel() <= std::numeric_limits<int>::max() &&
                    in_b.numel() <= std::numeric_limits<int>::max(),
                    "wvSpltK requires positive dimensions and 32-bit element indexing");
        TORCH_CHECK(in_a.size(1) % 8 == 0, "wvSpltK requires K to be a multiple of 8");
        TORCH_CHECK(CuCount > 0 && CuCount <= std::numeric_limits<int>::max(),
                    "wvSpltK CuCount must be a positive int32");
        at::assert_no_overlap(out_c, in_a);
        at::assert_no_overlap(out_c, in_b);
        auto M = in_a.size(0);
        auto K = in_a.size(1);
        int N = N_in;
        const at::cuda::OptionalCUDAGuard device_guard(device_of(in_a));
        if (in_a.scalar_type() == at::kBFloat16)
        {
                wvSpltK_bf16_(in_a.data_ptr(), in_b.data_ptr(), out_c.data_ptr(), M, K, N,
                             at::cuda::getCurrentCUDAStream(), CuCount);
                return;
        }
        wvSpltK_(in_a.data_ptr(), in_b.data_ptr(), out_c.data_ptr(), M, K, N,
                 at::cuda::getCurrentCUDAStream(), CuCount);
}

void LLGemmZZ(void *in_a, void *in_b, void *out_c, const int M, const int K,
              cudaStream_t stream, const int solidx);

void LLZZ(at::Tensor in_a, at::Tensor in_b, at::Tensor out_c,
          const int64_t solidx = 0)
{
        auto M = in_a.size(0);
        auto K = in_a.size(1);
        const at::cuda::OptionalCUDAGuard device_guard(device_of(in_a));
        LLGemmZZ(in_a.data_ptr(), in_b.data_ptr(), out_c.data_ptr(), M, K,
                 at::cuda::getCurrentCUDAStream(), solidx);
}
// instantiate the CPP template for T=float:
// template void AddGPU<float>(at::Tensor in_a, at::Tensor in_b, at::Tensor
// out_c);

void MMGPUKernel(float *in_a, float *in_b, float *out_c, int numARows,
                 int numAColumns, int numBRows, int numBColumns, int numCRows,
                 int numCColumns, cudaStream_t stream);

void MMCustomGPU(at::Tensor &in_a, at::Tensor &in_b, at::Tensor &out_c)
{
        auto matA_sizes{in_a.sizes()};
        auto matB_sizes{in_b.sizes()};
        auto matO_sizes{out_c.sizes()};
        const at::cuda::OptionalCUDAGuard device_guard(device_of(in_a));
        MMGPUKernel(in_a.data_ptr<float>(), in_b.data_ptr<float>(),
                    out_c.data_ptr<float>(), matA_sizes[0], matA_sizes[1],
                    matB_sizes[0], matB_sizes[1], matO_sizes[0], matO_sizes[1],
                    at::cuda::getCurrentCUDAStream());
}
