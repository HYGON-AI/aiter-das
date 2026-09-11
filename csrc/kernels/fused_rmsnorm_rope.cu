// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "hip/hip_runtime.h"
#include "hip/hip_bf16.h"
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <tuple>
#include "fused_rmsnorm_rope.h"

namespace aiter {

using shortx8_t = __attribute__((__vector_size__(8 * sizeof(short)))) short;
using fp32x4_t = __attribute__((__vector_size__(4 * sizeof(float)))) float;
using bf16_t = __hip_bfloat16;

constexpr int kVecSize = 8;
constexpr int kThreadsPerRow = 16;
constexpr int kHeadDim = 128;
constexpr int kHeadsPerBlock = 12;
constexpr int kBlockSize = kHeadsPerBlock * kThreadsPerRow;

__device__ __forceinline__ void rmsnorm_rope_hdim128_row(
    const bf16_t* current_input,
    const bf16_t* current_input_weight,
    const float* current_freqs,
    bf16_t* current_output,
    float eps,
    int lane)
{
    int col_index = lane * kVecSize;
    current_input += col_index;
    current_input_weight += col_index;
    current_freqs += col_index;
    current_output += col_index;

    union
    {
        shortx8_t raw;
        bf16_t bf16[8];
    }input_values, weight_values, freqs_values, output_values;

    union
    {
        fp32x4_t raw;
        float fp32[4];
    }freqs_values0, freqs_values1;


    input_values.raw = *((const shortx8_t *)current_input);
    weight_values.raw = *((const shortx8_t *)current_input_weight);
    freqs_values0.raw = *((const fp32x4_t *)(current_freqs + 0));
    freqs_values1.raw = *((const fp32x4_t *)(current_freqs + 4));

    float input0 = static_cast<float>(input_values.bf16[0]);
    float input1 = static_cast<float>(input_values.bf16[1]);
    float input2 = static_cast<float>(input_values.bf16[2]);
    float input3 = static_cast<float>(input_values.bf16[3]);
    float input4 = static_cast<float>(input_values.bf16[4]);
    float input5 = static_cast<float>(input_values.bf16[5]);
    float input6 = static_cast<float>(input_values.bf16[6]);
    float input7 = static_cast<float>(input_values.bf16[7]);

    float input_weight0 = static_cast<float>(weight_values.bf16[0]);
    float input_weight1 = static_cast<float>(weight_values.bf16[1]);
    float input_weight2 = static_cast<float>(weight_values.bf16[2]);
    float input_weight3 = static_cast<float>(weight_values.bf16[3]);
    float input_weight4 = static_cast<float>(weight_values.bf16[4]);
    float input_weight5 = static_cast<float>(weight_values.bf16[5]);
    float input_weight6 = static_cast<float>(weight_values.bf16[6]);
    float input_weight7 = static_cast<float>(weight_values.bf16[7]);

    float freqs0 = freqs_values0.fp32[0];
    float freqs1 = freqs_values0.fp32[1];
    float freqs2 = freqs_values0.fp32[2];
    float freqs3 = freqs_values0.fp32[3];
    float freqs4 = freqs_values1.fp32[0];
    float freqs5 = freqs_values1.fp32[1];
    float freqs6 = freqs_values1.fp32[2];
    float freqs7 = freqs_values1.fp32[3];

    float acc = 0;
    acc += input0 * input0 + input1 * input1;
    acc += input2 * input2 + input3 * input3;
    acc += input4 * input4 + input5 * input5;
    acc += input6 * input6 + input7 * input7;

    for(int offset = 8; offset > 0; offset >>= 1)
    {
        acc += __shfl_xor(acc, offset, 16);
    }
    float rms = rsqrt(acc / kHeadDim + eps);

    float x0 = input0 * rms * input_weight0;
    float x1 = input1 * rms * input_weight1;
    float x2 = input2 * rms * input_weight2;
    float x3 = input3 * rms * input_weight3;
    float x4 = input4 * rms * input_weight4;
    float x5 = input5 * rms * input_weight5;
    float x6 = input6 * rms * input_weight6;
    float x7 = input7 * rms * input_weight7;

    output_values.bf16[0] = static_cast<bf16_t>(x0 * freqs0 - x1 * freqs1);
    output_values.bf16[1] = static_cast<bf16_t>(x0 * freqs1 + x1 * freqs0);
    
    output_values.bf16[2] = static_cast<bf16_t>(x2 * freqs2 - x3 * freqs3);
    output_values.bf16[3] = static_cast<bf16_t>(x2 * freqs3 + x3 * freqs2);
    
    output_values.bf16[4] = static_cast<bf16_t>(x4 * freqs4 - x5 * freqs5);
    output_values.bf16[5] = static_cast<bf16_t>(x4 * freqs5 + x5 * freqs4);
    
    output_values.bf16[6] = static_cast<bf16_t>(x6 * freqs6 - x7 * freqs7);
    output_values.bf16[7] = static_cast<bf16_t>(x6 * freqs7 + x7 * freqs6);

    *((shortx8_t *)current_output) = output_values.raw;

}

struct TensorStrides3
{
    int64_t batch;
    int64_t sequence;
    int64_t head;
};

__device__ __forceinline__ int64_t row_offset(
    const TensorStrides3& strides, int batch_index, int sequence_index, int head_index)
{
    return batch_index * strides.batch + sequence_index * strides.sequence + head_index * strides.head;
}

__global__ void fused_rmsnorm_rope_hdim128_kernel(
    const bf16_t* __restrict__ input,
    const bf16_t* __restrict__ input_weight,
    const float* __restrict__ freqs,
    bf16_t* __restrict__ output,
    int num_head,
    TensorStrides3 input_strides,
    TensorStrides3 output_strides,
    float eps)
{
    __shared__ bf16_t shared_weight[kHeadDim];
    __shared__ float shared_freqs[kHeadDim];

    if(threadIdx.x < kHeadDim)
    {
        shared_weight[threadIdx.x] = input_weight[threadIdx.x];
        shared_freqs[threadIdx.x] = freqs[blockIdx.y * kHeadDim + threadIdx.x];
    }
    __syncthreads();

    int lane = threadIdx.x % kThreadsPerRow;
    int head_index = blockIdx.x * kHeadsPerBlock + threadIdx.x / kThreadsPerRow;
    if(head_index >= num_head)
    {
        return;
    }
    int sequence_index = blockIdx.y;
    int batch_index = blockIdx.z;
    rmsnorm_rope_hdim128_row(
        input + row_offset(input_strides, batch_index, sequence_index, head_index),
        shared_weight,
        shared_freqs,
        output + row_offset(output_strides, batch_index, sequence_index, head_index),
        eps,
        lane);
}

__global__ void fused_qk_rmsnorm_rope_hdim128_kernel(
    const bf16_t* __restrict__ q,
    const bf16_t* __restrict__ k,
    const bf16_t* __restrict__ q_weight,
    const bf16_t* __restrict__ k_weight,
    const float* __restrict__ freqs,
    bf16_t* __restrict__ q_output,
    bf16_t* __restrict__ k_output,
    int batch,
    int num_head,
    TensorStrides3 q_strides,
    TensorStrides3 k_strides,
    TensorStrides3 q_output_strides,
    TensorStrides3 k_output_strides,
    float eps)
{
    __shared__ bf16_t shared_weight[kHeadDim];
    __shared__ float shared_freqs[kHeadDim];

    int qk_index = blockIdx.z >= batch;
    int batch_index = blockIdx.z - qk_index * batch;
    if(threadIdx.x < kHeadDim)
    {
        const bf16_t* weight = qk_index == 0 ? q_weight : k_weight;
        shared_weight[threadIdx.x] = weight[threadIdx.x];
        shared_freqs[threadIdx.x] = freqs[blockIdx.y * kHeadDim + threadIdx.x];
    }
    __syncthreads();

    int lane = threadIdx.x % kThreadsPerRow;
    int head_index = blockIdx.x * kHeadsPerBlock + threadIdx.x / kThreadsPerRow;
    if(head_index >= num_head)
    {
        return;
    }
    int sequence_index = blockIdx.y;

    const bf16_t* input = qk_index == 0 ? q : k;
    bf16_t* output = qk_index == 0 ? q_output : k_output;
    TensorStrides3 input_strides = qk_index == 0 ? q_strides : k_strides;
    TensorStrides3 output_strides = qk_index == 0 ? q_output_strides : k_output_strides;
    rmsnorm_rope_hdim128_row(
        input + row_offset(input_strides, batch_index, sequence_index, head_index),
        shared_weight,
        shared_freqs,
        output + row_offset(output_strides, batch_index, sequence_index, head_index),
        eps,
        lane);
}


void fused_rmsnorm_rope_out(
    const torch::Tensor& input,
    const torch::Tensor& input_weight,
    const torch::Tensor& freqs,
    torch::Tensor& output,
    double eps)
{
    TORCH_CHECK(input.dim() == 4, "input must be 4D: [batch, seq_len, num_head, head_dim]");
    TORCH_CHECK(input_weight.dim() == 1, "input_weight must be 1D: [head_dim]");
    TORCH_CHECK(freqs.dim() == 2, "freqs must be 2D: [seq_len, head_dim]");
    TORCH_CHECK(output.dim() == 4, "output must be 4D: [batch, seq_len, num_head, head_dim]");
    TORCH_CHECK(input.sizes() == output.sizes(), "input and output must have the same shape");
    TORCH_CHECK(input.is_cuda() && input_weight.is_cuda() && freqs.is_cuda() && output.is_cuda(),
                "input, input_weight, freqs, and output must be CUDA tensors");
    TORCH_CHECK(input.device() == input_weight.device() && input.device() == freqs.device()
                    && input.device() == output.device(),
                "input, input_weight, freqs, and output must be on the same device");
    TORCH_CHECK(input.stride(-1) == 1 && output.stride(-1) == 1,
                "input and output must be contiguous in the last dimension");
    TORCH_CHECK(input_weight.is_contiguous(), "input_weight must be contiguous");
    TORCH_CHECK(freqs.is_contiguous(), "freqs must be contiguous");
    TORCH_CHECK(input.scalar_type() == input_weight.scalar_type(), "input and input_weight must have the same dtype");
    TORCH_CHECK(input.scalar_type() == output.scalar_type(), "input and output must have the same dtype");
    TORCH_CHECK(input.scalar_type() == at::kBFloat16, "fused_rmsnorm_rope only supports input bfloat16 for now");
    TORCH_CHECK(freqs.scalar_type() == at::kFloat, "fused_rmsnorm_rope only supports freqs fp32 for now");
    TORCH_CHECK(eps >= 0.0, "eps must be non-negative");

    int batch = input.size(0);
    int seq_len = input.size(1);
    int num_head = input.size(2);
    int head_dim = input.size(3);

    TORCH_CHECK(head_dim == 128, "fused_rmsnorm_rope only supports head_dim 128 for now");
    TORCH_CHECK(input_weight.numel() == head_dim, "input_weight must contain head_dim elements");
    TORCH_CHECK(freqs.size(0) >= seq_len && freqs.size(1) == head_dim,
                "freqs must have shape [at least seq_len, head_dim]");

    int head_groups = (num_head + kHeadsPerBlock - 1) / kHeadsPerBlock;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    TensorStrides3 input_strides{input.stride(0), input.stride(1), input.stride(2)};
    TensorStrides3 output_strides{output.stride(0), output.stride(1), output.stride(2)};
    fused_rmsnorm_rope_hdim128_kernel<<<dim3(head_groups, seq_len, batch), kBlockSize, 0, stream>>>(
        reinterpret_cast<const bf16_t*>(input.data_ptr()),
        reinterpret_cast<const bf16_t*>(input_weight.data_ptr()),
        reinterpret_cast<const float*>(freqs.data_ptr()),
        reinterpret_cast<bf16_t*>(output.data_ptr()),
        num_head,
        input_strides,
        output_strides,
        static_cast<float>(eps));
}

void fused_rmsnorm_rope(
    const torch::Tensor& input,
    const torch::Tensor& input_weight,
    const torch::Tensor& freqs,
    torch::Tensor& output)
{
    fused_rmsnorm_rope_out(input, input_weight, freqs, output, 1e-6);
}

torch::Tensor fused_rmsnorm_rope_op(
    const torch::Tensor& input,
    const torch::Tensor& input_weight,
    const torch::Tensor& freqs,
    double eps)
{
    auto output = at::empty_like(input, input.options(), at::MemoryFormat::Preserve);
    fused_rmsnorm_rope_out(input, input_weight, freqs, output, eps);
    return output;
}

torch::Tensor fused_rmsnorm_rope_meta(
    const torch::Tensor& input,
    const torch::Tensor& input_weight,
    const torch::Tensor& freqs,
    double eps)
{
    return at::empty_like(input, input.options(), at::MemoryFormat::Preserve);
}

std::tuple<torch::Tensor, torch::Tensor> fused_qk_rmsnorm_rope_op(
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& q_weight,
    const torch::Tensor& k_weight,
    const torch::Tensor& freqs,
    double eps)
{
    TORCH_CHECK(q.dim() == 4 && k.dim() == 4,
                "q and k must be 4D: [batch, seq_len, num_head, head_dim]");
    TORCH_CHECK(q.sizes() == k.sizes(), "q and k must have the same shape");
    TORCH_CHECK(q_weight.dim() == 1 && k_weight.dim() == 1,
                "q_weight and k_weight must be 1D: [head_dim]");
    TORCH_CHECK(freqs.dim() == 2, "freqs must be 2D: [seq_len, head_dim]");
    TORCH_CHECK(q.is_cuda() && k.is_cuda() && q_weight.is_cuda() && k_weight.is_cuda() && freqs.is_cuda(),
                "q, k, q_weight, k_weight, and freqs must be CUDA tensors");
    TORCH_CHECK(q.device() == k.device() && q.device() == q_weight.device()
                    && q.device() == k_weight.device() && q.device() == freqs.device(),
                "q, k, q_weight, k_weight, and freqs must be on the same device");
    TORCH_CHECK(q.stride(-1) == 1 && k.stride(-1) == 1,
                "q and k must be contiguous in the last dimension");
    TORCH_CHECK(q_weight.is_contiguous() && k_weight.is_contiguous(),
                "q_weight and k_weight must be contiguous");
    TORCH_CHECK(freqs.is_contiguous(), "freqs must be contiguous");
    TORCH_CHECK(q.scalar_type() == at::kBFloat16 && k.scalar_type() == at::kBFloat16,
                "fused_qk_rmsnorm_rope only supports q and k bfloat16 for now");
    TORCH_CHECK(q_weight.scalar_type() == q.scalar_type() && k_weight.scalar_type() == k.scalar_type(),
                "q/q_weight and k/k_weight must have the same dtype");
    TORCH_CHECK(freqs.scalar_type() == at::kFloat,
                "fused_qk_rmsnorm_rope only supports freqs fp32 for now");
    TORCH_CHECK(eps >= 0.0, "eps must be non-negative");

    int batch = q.size(0);
    int seq_len = q.size(1);
    int num_head = q.size(2);
    int head_dim = q.size(3);
    TORCH_CHECK(head_dim == 128, "fused_qk_rmsnorm_rope only supports head_dim 128 for now");
    TORCH_CHECK(q_weight.numel() == head_dim && k_weight.numel() == head_dim,
                "q_weight and k_weight must contain head_dim elements");
    TORCH_CHECK(freqs.size(0) >= seq_len && freqs.size(1) == head_dim,
                "freqs must have shape [at least seq_len, head_dim]");

    auto q_output = at::empty_like(q, q.options(), at::MemoryFormat::Preserve);
    auto k_output = at::empty_like(k, k.options(), at::MemoryFormat::Preserve);
    int head_groups = (num_head + kHeadsPerBlock - 1) / kHeadsPerBlock;

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(q));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    TensorStrides3 q_strides{q.stride(0), q.stride(1), q.stride(2)};
    TensorStrides3 k_strides{k.stride(0), k.stride(1), k.stride(2)};
    TensorStrides3 q_output_strides{
        q_output.stride(0), q_output.stride(1), q_output.stride(2)};
    TensorStrides3 k_output_strides{
        k_output.stride(0), k_output.stride(1), k_output.stride(2)};
    // Q and K use independent blocks in one launch so the scheduler retains
    // the occupancy of the single-input kernel.
    fused_qk_rmsnorm_rope_hdim128_kernel<<<dim3(head_groups, seq_len, batch * 2), kBlockSize, 0, stream>>>(
        reinterpret_cast<const bf16_t*>(q.data_ptr()),
        reinterpret_cast<const bf16_t*>(k.data_ptr()),
        reinterpret_cast<const bf16_t*>(q_weight.data_ptr()),
        reinterpret_cast<const bf16_t*>(k_weight.data_ptr()),
        reinterpret_cast<const float*>(freqs.data_ptr()),
        reinterpret_cast<bf16_t*>(q_output.data_ptr()),
        reinterpret_cast<bf16_t*>(k_output.data_ptr()),
        batch,
        num_head,
        q_strides,
        k_strides,
        q_output_strides,
        k_output_strides,
        static_cast<float>(eps));
    return {q_output, k_output};
}

std::tuple<torch::Tensor, torch::Tensor> fused_qk_rmsnorm_rope_meta(
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& q_weight,
    const torch::Tensor& k_weight,
    const torch::Tensor& freqs,
    double eps)
{
    return {
        at::empty_like(q, q.options(), at::MemoryFormat::Preserve),
        at::empty_like(k, k.options(), at::MemoryFormat::Preserve)};
}

} // namespace aiter
