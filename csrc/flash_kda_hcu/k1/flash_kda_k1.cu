// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// K1 的主机入口：参数校验、workspace 分配视图与两套 kernel 实例的实例化。

#include "flash_kda_k1.h"
#include "flash_kda_k1_layout.cuh"
#include "flash_kda_k1_utils.cuh"
#include "flash_kda_varlen_metadata.cuh"
#include "flash_kda_launch.h"


#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/hip/HIPException.h>
#include <hip/hip_bf16.h>
#include <hip/hip_runtime.h>

#include <cmath>
#include <limits>
#include <string>
#include <type_traits>

#include "flash_kda_k1_kernel.cuh"

namespace
{

struct DirectGeometry
{
    int64_t batch;
    int64_t tokens;
    int64_t heads;
    int64_t chunks;
    int64_t lanes;
    bool has_bias;
    bool beta_bf16;
    bool tail;   // 【A4】tokens % 16 != 0 => 用 FixedTailInfo 实例
};

DirectGeometry direct_geometry(
    const torch::Tensor& q,
    const torch::Tensor& k,
    const torch::Tensor& g,
    const torch::Tensor& beta,
    const torch::Tensor& A_log,
    const torch::Tensor& dt_bias,
    double scale,
    double lower_bound)
{
    TORCH_CHECK(q.is_cuda() && q.is_contiguous()
                    && q.scalar_type() == at::kBFloat16
                    && q.dim() == 4 && q.size(3) == kda_detail::kDim,
                "q must be contiguous GPU BF16 [B,T,H,128]");
    const auto device = q.device();
    for(const auto& tensor : {k, g})
        TORCH_CHECK(tensor.is_cuda() && tensor.device() == device
                        && tensor.is_contiguous()
                        && tensor.scalar_type() == at::kBFloat16
                        && tensor.sizes() == q.sizes(),
                    "k/g must be contiguous GPU BF16 matching q");
    DirectGeometry geometry{};
    geometry.batch = q.size(0);
    geometry.tokens = q.size(1);
    geometry.heads = q.size(2);
    geometry.lanes = geometry.batch * geometry.heads;
    // 【A4】接受任意正 T：块数用 ceil；最后一个块由 FixedTailInfo 实例按
    // valid_tokens 掩蔽。仍然要求 tokens 能放进 kernel 的 int 形参。
    TORCH_CHECK(geometry.lanes > 0 && geometry.lanes <= 65535
                    && geometry.tokens > 0
                    && geometry.tokens <= std::numeric_limits<int>::max(),
                "kda_k1_forward requires B*H in [1,65535] and T in [1,INT_MAX]");
    TORCH_CHECK(beta.is_cuda() && beta.device() == device
                    && beta.is_contiguous()
                    && (beta.scalar_type() == at::kFloat
                        || beta.scalar_type() == at::kBFloat16)
                    && beta.dim() == 3 && beta.size(0) == geometry.batch
                    && beta.size(1) == geometry.tokens
                    && beta.size(2) == geometry.heads,
                "beta must be contiguous GPU FP32/BF16 [B,T,H]");
    TORCH_CHECK(A_log.is_cuda() && A_log.device() == device
                    && A_log.is_contiguous()
                    && A_log.scalar_type() == at::kFloat
                    && A_log.dim() == 1 && A_log.numel() == geometry.heads,
                "A_log must be contiguous GPU FP32 [H]");
    geometry.has_bias = dt_bias.numel() != 0;
    TORCH_CHECK(!geometry.has_bias
                    || (dt_bias.is_cuda() && dt_bias.device() == device
                        && dt_bias.is_contiguous()
                        && dt_bias.scalar_type() == at::kFloat
                        && dt_bias.dim() == 2
                        && dt_bias.size(0) == geometry.heads
                        && dt_bias.size(1) == kda_detail::kDim),
                "dt_bias must be empty or contiguous GPU FP32 [H,128]");
    TORCH_CHECK(std::isfinite(scale)
                    && std::abs(scale) <= 3.3895313892515355e38,
                "scale must be finite within BF16 range");
    TORCH_CHECK(std::isfinite(lower_bound)
                    && lower_bound >= -5.0 && lower_bound <= 0.0,
                "lower_bound must be in [-5,0]");
    hipDeviceProp_t properties;
    C10_HIP_CHECK(hipGetDeviceProperties(&properties, q.get_device()));
    TORCH_CHECK(std::string(properties.gcnArchName).rfind("gfx936", 0) == 0,
                "kda_k1_forward currently requires gfx936");
    geometry.chunks =
        (geometry.tokens + kda_detail::kChunk - 1) / kda_detail::kChunk;
    geometry.tail = geometry.tokens % kda_detail::kChunk != 0;
    geometry.beta_bf16 = beta.scalar_type() == at::kBFloat16;
    return geometry;
}

} // namespace

void kda_k1_forward(
    torch::Tensor q,
    torch::Tensor k,
    torch::Tensor g,
    torch::Tensor beta,
    torch::Tensor A_log,
    torch::Tensor dt_bias,
    double scale,
    double lower_bound,
    torch::Tensor ws_kd_a,
    torch::Tensor ws_kr_a,
    torch::Tensor ws_inv_a,
    torch::Tensor ws_mqk_a,
    torch::Tensor beta_sigmoid,
    bool write_beta_fp32)
{
    const DirectGeometry geometry =
        direct_geometry(q, k, g, beta, A_log, dt_bias, scale, lower_bound);
    const int64_t chunks = geometry.chunks;
    const int64_t lanes = geometry.lanes;
    const int64_t p = geometry.lanes * chunks;
    const auto& device = q.device();
    const auto check = [&](const torch::Tensor& tensor, at::ScalarType dtype,
                           c10::IntArrayRef sizes, const char* name) {
        TORCH_CHECK(tensor.is_cuda() && tensor.device() == device
                        && tensor.is_contiguous()
                        && tensor.scalar_type() == dtype
                        && tensor.sizes() == sizes,
                    name, " must be contiguous GPU with the expected dtype/shape");
    };
    check(ws_kd_a, at::kBFloat16, {p, 2, 8, 16, 16}, "ws_kd_a");
    check(ws_kr_a, at::kBFloat16, {p, 9, 16, 16}, "ws_kr_a");
    check(ws_inv_a, at::kBFloat16, {p, 1, 1, 16, 16}, "ws_inv_a");
    check(ws_mqk_a, at::kBFloat16, {p, 1, 1, 16, 16}, "ws_mqk_a");
    check(beta_sigmoid, at::kFloat, {p, 16}, "beta_sigmoid");

    flash_kda::detail::ForwardParams params;
    params.batch = geometry.batch;
    params.tokens = geometry.tokens;
    params.heads = geometry.heads;
    params.sequence_count = geometry.batch;
    params.head_stride_chunks = chunks * geometry.batch;
    params.workspace_chunks = p;
    params.tail = geometry.tail;
    params.has_bias = geometry.has_bias;
    params.beta_bf16 = geometry.beta_bf16;
    params.write_beta_fp32 = write_beta_fp32;
    params.scale = static_cast<float>(scale);
    params.lower_bound = static_cast<float>(lower_bound);
    params.q = q.data_ptr();
    params.k = k.data_ptr();
    params.g = g.data_ptr();
    params.beta = beta.data_ptr();
    params.A_log = A_log.data_ptr<float>();
    params.dt_bias = geometry.has_bias ? dt_bias.data_ptr<float>() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kd_a.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_kr_a.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv_a.data_ptr());
    views.mqk = reinterpret_cast<unsigned short *>(ws_mqk_a.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(q));
    flash_kda::detail::launch_k1(params, views, at::hip::getCurrentHIPStream(q.get_device()));
    C10_HIP_CHECK(hipGetLastError());
}


// ===========================================================================
// P1：GPU metadata（独立小 kernel；不占 peer K1 的 LDS 预算）
// ===========================================================================
void kda_build_varlen_metadata(
    torch::Tensor cu_seqlens,
    torch::Tensor chunk_info,
    torch::Tensor sequence_info)
{
    const auto& device = cu_seqlens.device();
    TORCH_CHECK(cu_seqlens.is_cuda() && cu_seqlens.is_contiguous()
                    && cu_seqlens.dim() == 1,
                "cu_seqlens must be a contiguous CUDA 1-D tensor");
    const auto index_dtype = cu_seqlens.scalar_type();
    TORCH_CHECK(index_dtype == at::kInt || index_dtype == at::kLong,
                "cu_seqlens must be INT32 or INT64");
    TORCH_CHECK(chunk_info.is_cuda() && chunk_info.is_contiguous()
                    && chunk_info.scalar_type() == at::kLong
                    && chunk_info.dim() == 2 && chunk_info.size(1) == 2,
                "chunk_info must be contiguous CUDA INT64 [Qcap,2]");
    TORCH_CHECK(sequence_info.is_cuda() && sequence_info.is_contiguous()
                    && sequence_info.scalar_type() == at::kLong
                    && sequence_info.dim() == 2 && sequence_info.size(1) == 3,
                "sequence_info must be contiguous CUDA INT64 [N,3]");
    TORCH_CHECK(chunk_info.device() == device && sequence_info.device() == device,
                "metadata tensors must share a device");
    const int64_t sequences = cu_seqlens.numel() - 1;
    TORCH_CHECK(sequences >= 1, "cu_seqlens must describe at least one sequence");
    TORCH_CHECK(sequence_info.size(0) == sequences,
                "sequence_info must be [N,3] with N = cu_seqlens.numel()-1");
    const int64_t capacity = chunk_info.size(0);
    TORCH_CHECK(capacity >= 1, "chunk_info capacity must be >= 1");
    TORCH_CHECK(sequences <= static_cast<int64_t>(std::numeric_limits<int>::max())
                    && capacity <= static_cast<int64_t>(std::numeric_limits<int>::max()),
                "metadata sizes exceed int range");

    flash_kda::detail::ForwardParams params;
    params.sequence_count = sequences;
    params.head_stride_chunks = capacity;
    params.cu_int32 = index_dtype == at::kInt;
    params.cu_seqlens = params.cu_int32 ? nullptr : cu_seqlens.data_ptr<int64_t>();
    params.cu_seqlens32 = params.cu_int32 ? cu_seqlens.data_ptr<int>() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.chunk_info = chunk_info.data_ptr<int64_t>();
    views.sequence_info = sequence_info.data_ptr<int64_t>();

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(cu_seqlens));
    flash_kda::detail::launch_varlen_metadata(params, views,
                                             at::hip::getCurrentHIPStream(cu_seqlens.get_device()));
    C10_HIP_CHECK(hipGetLastError());
}


// ===========================================================================
// P2：peer direct **变长** host 入口（B=1，packed 输入，chunk_info 驱动）
// ===========================================================================
void kda_k1_varlen_forward(
    torch::Tensor q,
    torch::Tensor k,
    torch::Tensor g,
    torch::Tensor beta,
    torch::Tensor A_log,
    torch::Tensor dt_bias,
    double scale,
    double lower_bound,
    torch::Tensor ws_kd_a,
    torch::Tensor ws_kr_a,
    torch::Tensor ws_inv_a,
    torch::Tensor ws_mqk_a,
    torch::Tensor beta_sigmoid,
    torch::Tensor chunk_info)
{
    // 这个入口**不**复用 direct_geometry：那个校验要求 T>0 且 T%16==0，
    // 变长必须允许 T_total==0 与尾块。这里只做 packed 形状/容量/地址范围校验。
    const auto& device = q.device();
    const auto expect = [&](const torch::Tensor& tensor, at::ScalarType dtype,
                            c10::IntArrayRef sizes, const char* name) {
        TORCH_CHECK(tensor.is_cuda() && tensor.device() == device
                        && tensor.is_contiguous()
                        && tensor.scalar_type() == dtype && tensor.sizes() == sizes,
                    name, " must be contiguous GPU with the expected dtype/shape");
    };
    TORCH_CHECK(q.dim() == 4 && q.size(0) == 1, "peer varlen K1 requires B=1");
    const int64_t total_tokens = q.size(1);
    const int64_t heads = q.size(2);
    const int64_t dim = q.size(3);
    TORCH_CHECK(dim == kDim, "peer varlen K1 requires K=V=128");
    TORCH_CHECK(total_tokens >= 0 && heads >= 1, "invalid packed shape");
    TORCH_CHECK(heads <= 65535, "grid.y (H) exceeds the launcher limit");
    expect(q, at::kBFloat16, {1, total_tokens, heads, dim}, "q");
    expect(k, at::kBFloat16, {1, total_tokens, heads, dim}, "k");
    expect(g, at::kBFloat16, {1, total_tokens, heads, dim}, "g");
    expect(beta, at::kFloat, {1, total_tokens, heads}, "beta");
    expect(A_log, at::kFloat, {heads}, "A_log");
    const bool has_bias = dt_bias.defined() && dt_bias.numel() > 0;
    if(has_bias)
        expect(dt_bias, at::kFloat, {heads * dim}, "dt_bias");
    TORCH_CHECK(chunk_info.is_cuda() && chunk_info.device() == device
                    && chunk_info.is_contiguous()
                    && chunk_info.scalar_type() == at::kLong && chunk_info.dim() == 2
                    && chunk_info.size(1) == 2,
                "chunk_info must be contiguous CUDA INT64 [Qcap,2]");
    const int64_t capacity = chunk_info.size(0);
    TORCH_CHECK(capacity >= 1, "chunk_info capacity must be >= 1");
    TORCH_CHECK(capacity >= (total_tokens + kChunk - 1) / kChunk,
                "chunk_info capacity is smaller than ceil(T_total/16)");
    TORCH_CHECK(capacity <= static_cast<int64_t>(std::numeric_limits<int>::max()) / kChunk,
                "Qcap exceeds INT_MAX/16");
    const int64_t p = heads * capacity;
    // 保守地址上限：与 K2 的 MUBUF 32 位偏移约束一致。
    TORCH_CHECK(capacity * 8192 < (int64_t(1) << 31),
                "Qcap*8192 must be < 2^31 (MUBUF soffset)");
    TORCH_CHECK(static_cast<double>(total_tokens) * heads * dim * 2 <= 4294967295.0,
                "T_total*H*128*2 must fit in UINT32_MAX");
    expect(ws_kd_a, at::kBFloat16, {p, 2, 8, 16, 16}, "ws_kd_a");
    expect(ws_kr_a, at::kBFloat16, {p, 9, 16, 16}, "ws_kr_a");
    expect(ws_inv_a, at::kBFloat16, {p, 1, 1, 16, 16}, "ws_inv_a");
    expect(ws_mqk_a, at::kBFloat16, {p, 1, 1, 16, 16}, "ws_mqk_a");
    expect(beta_sigmoid, at::kFloat, {p, kChunk}, "beta_sigmoid");

    flash_kda::detail::ForwardParams params;
    params.batch = 1;
    params.tokens = total_tokens;
    params.heads = heads;
    params.head_stride_chunks = capacity;
    params.workspace_chunks = p;
    params.is_varlen = true;
    params.has_bias = has_bias;
    params.beta_bf16 = beta.scalar_type() == at::kBFloat16;
    params.write_beta_fp32 = true;
    params.scale = static_cast<float>(scale);
    params.lower_bound = static_cast<float>(lower_bound);
    params.q = q.data_ptr();
    params.k = k.data_ptr();
    params.g = g.data_ptr();
    params.beta = beta.data_ptr();
    params.A_log = A_log.data_ptr<float>();
    params.dt_bias = has_bias ? dt_bias.data_ptr<float>() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kd_a.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_kr_a.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv_a.data_ptr());
    views.mqk = reinterpret_cast<unsigned short *>(ws_mqk_a.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();
    views.chunk_info = chunk_info.data_ptr<int64_t>();

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device_of(q));
    flash_kda::detail::launch_k1(params, views, at::hip::getCurrentHIPStream(q.get_device()));
    C10_HIP_CHECK(hipGetLastError());
}

// ===========================================================================
// raw launch：只做模板选择与启动（统一 forward 与本文件的 checked 入口共用）
// ===========================================================================
namespace flash_kda
{
    namespace detail
    {

        void launch_k1(const ForwardParams &params, const WorkspaceViews &views,
                       hipStream_t stream)
        {
            const int64_t chunks = params.is_varlen
                                       ? params.head_stride_chunks
                                       : (params.tokens + kda_detail::kChunk - 1) / kda_detail::kChunk;
            const dim3 grid(static_cast<unsigned int>(chunks),
                            static_cast<unsigned int>(params.is_varlen
                                                          ? params.heads
                                                          : params.batch * params.heads));
            void *beta_ptr = const_cast<void *>(params.beta);
            const auto launch = [&](auto has_bias_tag, auto beta_bf16_tag, auto write_fp32_tag,
                                    auto... metadata)
            {
                hipLaunchKernelGGL(
                    (kda_k1_kernel<decltype(has_bias_tag)::value,
                                   decltype(beta_bf16_tag)::value,
                                   decltype(write_fp32_tag)::value,
                                   decltype(metadata)...>),
                    grid, dim3(kThreads), 0, stream,
                    static_cast<const at::BFloat16 *>(params.q),
                    static_cast<const at::BFloat16 *>(params.k),
                    static_cast<const at::BFloat16 *>(params.g),
                    beta_ptr, params.A_log, params.dt_bias,
                    reinterpret_cast<peer_u16 *>(views.kdqd),
                    reinterpret_cast<peer_u16 *>(views.krgt),
                    reinterpret_cast<peer_u16 *>(views.inv),
                    reinterpret_cast<peer_u16 *>(views.mqk),
                    views.beta_sigmoid,
                    static_cast<int>(params.tokens), static_cast<int>(params.heads),
                    static_cast<int>(chunks), params.scale,
                    static_cast<float>(params.lower_bound * 1.4426950408889634),
                    metadata...);
            };
            const auto dispatch = [&](auto... metadata)
            {
                if(params.write_beta_fp32)
                {
                    if(params.has_bias)
                    {
                        if(params.beta_bf16)
                            launch(std::true_type{}, std::true_type{}, std::true_type{},
                                   metadata...);
                        else
                            launch(std::true_type{}, std::false_type{}, std::true_type{},
                                   metadata...);
                    }
                    else if(params.beta_bf16)
                        launch(std::false_type{}, std::true_type{}, std::true_type{},
                               metadata...);
                    else
                        launch(std::false_type{}, std::false_type{}, std::true_type{},
                               metadata...);
                }
                else if(params.has_bias)
                {
                    if(params.beta_bf16)
                        launch(std::true_type{}, std::true_type{}, std::false_type{},
                               metadata...);
                    else
                        launch(std::true_type{}, std::false_type{}, std::false_type{},
                               metadata...);
                }
                else if(params.beta_bf16)
                    launch(std::false_type{}, std::true_type{}, std::false_type{},
                           metadata...);
                else
                    launch(std::false_type{}, std::false_type{}, std::false_type{},
                           metadata...);
            };
            if(params.is_varlen)
                dispatch(kda_peer::VarlenInfo{views.chunk_info,
                                              static_cast<int>(params.head_stride_chunks)});
            else if(params.tail)
                dispatch(kda_peer::FixedTailInfo{static_cast<int>(params.tokens)});
            else
                dispatch();
        }

        void launch_varlen_metadata(const ForwardParams &params, const WorkspaceViews &views,
                                    hipStream_t stream)
        {
            const dim3 grid(1);
            const dim3 block(kPeerMetaThreads);
            if(params.cu_int32)
                hipLaunchKernelGGL((build_varlen_metadata<int>), grid, block, 0, stream,
                                   params.cu_seqlens32,
                                   static_cast<int>(params.sequence_count),
                                   static_cast<int>(params.head_stride_chunks),
                                   views.chunk_info, views.sequence_info);
            else
                hipLaunchKernelGGL((build_varlen_metadata<int64_t>), grid, block, 0, stream,
                                   params.cu_seqlens,
                                   static_cast<int>(params.sequence_count),
                                   static_cast<int>(params.head_stride_chunks),
                                   views.chunk_info, views.sequence_info);
        }

    } // namespace detail
} // namespace flash_kda
