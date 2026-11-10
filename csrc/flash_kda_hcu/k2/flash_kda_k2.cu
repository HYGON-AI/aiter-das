// SPDX-License-Identifier: MIT
//
// FlashKDA 定长 / packed 变长 K2（gfx936）的主机入口。
//
// 唯一实现：4 wave（每 CTA 256 线程）× 每 wave 16 个 V 列、kd/qd 双缓冲 LDS、
// kr/gt 合并区单缓冲、ASM split-step（每 chunk 两条边界等待）。
// 模板维度只保留真实输入差异：
//   FullChunks  定长满块（T % 16 == 0）/ 尾块（掩蔽无效 token）
//   StateBf16   外部状态 dtype（FP32 / BF16；内部递推恒 FP32）
//   IsVarlen    定长索引 / packed 变长 sequence_info 索引
//
// workspace 布局（与 K1 的写侧契约一致，字节数不变）：
//   ws_kdqd [P,2,8,16,16] BF16  每 chunk 8 KiB：kd 4 KiB，紧跟 qd 4 KiB
//   ws_krgt [P,9,16,16]   BF16  每 chunk 4608 B：kr 4 KiB，紧跟 gt 512 B
//   ws_inv / ws_mqk        FP16  [P,1,1,16,16]
//   beta_sigmoid           FP32  [P,16]
// 索引 workspace_chunk_index = head * workspace_head_stride_chunks + sequence_chunk_offset + chunk。

#include <ATen/hip/HIPContext.h>
#include <hip/hip_bf16.h>

#include <hip/hip_runtime.h>
#include <torch/extension.h>


#include "flash_kda_launch.h"
#include "flash_kda_hcu.h"
#include "flash_kda_k2_kernel.cuh"

void kda_k2_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    const torch::Tensor &initial_state,
    torch::Tensor &final_state,
    bool state_v_first)
{
    TORCH_CHECK(v.is_cuda() && v.is_contiguous() && v.scalar_type() == at::kBFloat16,
                "C16 K2 v must be contiguous CUDA BF16");
    TORCH_CHECK(v.dim() == 4 && v.size(3) == kValueDim, "C16 K2 v must be [B,T,H,128]");
    const int B = static_cast<int>(v.size(0));
    const int T = static_cast<int>(v.size(1));
    const int H = static_cast<int>(v.size(2));
    const int chunks = (T + kChunkSize - 1) / kChunkSize;
    const int workspace_head_stride_chunks = B * chunks;
    const int P = H * workspace_head_stride_chunks;
    check_c16_tensor(ws_kdqd, "ws_kdqd", at::kBFloat16, {P, 2, 8, 16, 16});
    check_c16_tensor(ws_krgt, "ws_krgt", at::kBFloat16, {P, 9, 16, 16});
    check_c16_tensor(ws_inv, "ws_inv", at::kBFloat16, {P, 1, 1, 16, 16});
    check_c16_tensor(ws_mqk, "ws_mqk", at::kBFloat16, {P, 1, 1, 16, 16});
    check_c16_tensor(beta_sigmoid, "beta_sigmoid", at::kFloat, {P, kChunkSize});
    check_c16_tensor(out, "out", at::kBFloat16, {B, T, H, kValueDim});
    const bool has_initial = initial_state.defined() && initial_state.numel() > 0;
    const bool store_final = final_state.defined() && final_state.numel() > 0;
    // 外部定长 state 只允许 FP32 / BF16；初态与终态非空时必须同 dtype
    // （不交叉支持，避免无关实例与静默转换）。
    const at::ScalarType state_dtype = has_initial
                                           ? initial_state.scalar_type()
                                           : (store_final ? final_state.scalar_type()
                                                          : at::kFloat);
    TORCH_CHECK(state_dtype == at::kFloat || state_dtype == at::kBFloat16,
                "C16 K2 state must be FP32 or BF16");
    // 两种外部布局形状不同：KV 是 [N,H,K,V]，VK 是 [N,H,V,K]。
    const int64_t state_dim0 = state_v_first ? kValueDim : kKeyDim;
    const int64_t state_dim1 = state_v_first ? kKeyDim : kValueDim;
    if (has_initial)
    {
        TORCH_CHECK(initial_state.scalar_type() == state_dtype,
                    "C16 K2 initial_state dtype must match final_state dtype");
        check_c16_tensor(initial_state, "initial_state", state_dtype, {B, H, state_dim0, state_dim1});
    }
    if (store_final)
    {
        TORCH_CHECK(final_state.scalar_type() == state_dtype,
                    "C16 K2 final_state dtype must match initial_state dtype");
        check_c16_tensor(final_state, "final_state", state_dtype, {B, H, state_dim0, state_dim1});
    }
    for (const auto &tensor : {ws_kdqd, ws_krgt, ws_inv, ws_mqk, beta_sigmoid, out})
        TORCH_CHECK(tensor.device() == v.device(), "C16 K2 tensors must share a device");
    if (has_initial)
        TORCH_CHECK(initial_state.device() == v.device(), "initial_state must share a device");
    if (store_final)
        TORCH_CHECK(final_state.device() == v.device(), "final_state must share a device");
    const auto stream = at::hip::getCurrentHIPStream(v.get_device());
    flash_kda::detail::ForwardParams params;
    params.batch = B;
    params.tokens = T;
    params.heads = H;
    params.sequence_count = B;
    params.head_stride_chunks = workspace_head_stride_chunks;
    params.workspace_chunks = P;
    params.has_initial = has_initial;
    params.store_final = store_final;
    params.state_bf16 = state_dtype == at::kBFloat16;
    params.state_v_first = state_v_first;
    params.v = v.data_ptr();
    params.out = out.data_ptr();
    params.initial_state = has_initial ? initial_state.data_ptr() : nullptr;
    params.final_state = store_final ? final_state.data_ptr() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kdqd.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_krgt.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv.data_ptr());
    views.mqk = reinterpret_cast<unsigned short *>(ws_mqk.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();

    flash_kda::detail::launch_k2(params, views, stream);
    TORCH_CHECK(hipGetLastError() == hipSuccess, "C16 K2 launch failed");
}

// ============================================================================
// packed 变长 K2（一次 launch 处理 N 条序列）
//
//   v             BF16 CUDA contiguous [1, T_total, H, 128]（允许 T_total=0）
//   beta_sigmoid  FP32 CUDA contiguous [P, 16]
//   sequence_info INT64 CUDA contiguous [N,3]（AoS）：
//                   [:,0] = sequence_token_offset  本序列全局 packed token 起点
//                   [:,1] = L                      本序列长度（允许 0）
//                   [:,2] = chunk0                 本序列在每个 head 的 chunk 槽起点
//   workspace     head-major：workspace_chunk_index(head,s,c) = head*Qcap + chunk0[s] + c
//   状态          [N,H,128,128]，FP32 或 BF16
//
// 本入口**只实例化生产组合**（4 wave / 16 V 列 / ASM split-step），且固定
// FullChunks=false —— packed 总 T%16 为 0 也不代表每条序列都无尾块。
// ============================================================================
void kda_k2_varlen_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    const torch::Tensor &initial_state,
    torch::Tensor &final_state,
    const torch::Tensor &sequence_info,
    bool state_v_first)
{
    TORCH_CHECK(v.is_cuda() && v.is_contiguous() && v.scalar_type() == at::kBFloat16,
                "C16 K2 varlen v must be contiguous CUDA BF16");
    TORCH_CHECK(v.dim() == 4 && v.size(0) == 1 && v.size(3) == kValueDim,
                "C16 K2 varlen v must be [1,T_total,H,128]");
    const int T = static_cast<int>(v.size(1));
    const int H = static_cast<int>(v.size(2));
    TORCH_CHECK(T >= 0 && H > 0, "C16 K2 varlen requires T_total >= 0 and H > 0");
    TORCH_CHECK(sequence_info.is_cuda() && sequence_info.is_contiguous() &&
                    sequence_info.scalar_type() == at::kLong &&
                    sequence_info.dim() == 2 && sequence_info.size(1) == 3,
                "C16 K2 varlen sequence_info must be contiguous INT64 CUDA [N,3]");
    TORCH_CHECK(sequence_info.size(0) >= 1, "C16 K2 varlen requires N >= 1 sequences");
    // N 只由形状推出：**不回读** sequence_info 的任何 GPU 值。
    // GPU 元数据内容有效性是 K1/metadata 生产者的前置契约。
    const int N = static_cast<int>(sequence_info.size(0));
    const int64_t P = ws_kdqd.size(0);
    TORCH_CHECK(P > 0 && P % H == 0, "C16 K2 varlen requires workspace P divisible by H");
    const int Qcap = static_cast<int>(P / H);
    TORCH_CHECK(static_cast<int64_t>(N) * H <= 65535,
                "C16 K2 varlen grid.y = N*H exceeds the launcher limit");
    check_c16_tensor(ws_kdqd, "ws_kdqd", at::kBFloat16, {P, 2, 8, 16, 16});
    check_c16_tensor(ws_krgt, "ws_krgt", at::kBFloat16, {P, 9, 16, 16});
    check_c16_tensor(ws_inv, "ws_inv", at::kBFloat16, {P, 1, 1, 16, 16});
    check_c16_tensor(ws_mqk, "ws_mqk", at::kBFloat16, {P, 1, 1, 16, 16});
    check_c16_tensor(beta_sigmoid, "beta_sigmoid", at::kFloat, {P, kChunkSize});
    check_c16_tensor(out, "out", at::kBFloat16, {1, T, H, kValueDim});
    const bool has_initial = initial_state.defined() && initial_state.numel() > 0;
    const bool store_final = final_state.defined() && final_state.numel() > 0;
    // 状态 dtype 分派与定长入口同一套语义：初/终态必须同 dtype；都为空 → FP32。
    at::ScalarType state_dtype = at::kFloat;
    if (has_initial)
        state_dtype = initial_state.scalar_type();
    if (store_final)
    {
        TORCH_CHECK(!has_initial || final_state.scalar_type() == state_dtype,
                    "C16 K2 varlen initial_state/final_state must share dtype");
        state_dtype = final_state.scalar_type();
    }
    TORCH_CHECK(state_dtype == at::kFloat || state_dtype == at::kBFloat16,
                "C16 K2 varlen state must be FP32 or BF16");
    // 与定长入口同一套布局语义：KV 是 [N,H,K,V]，VK 是 [N,H,V,K]。
    const int64_t state_dim0 = state_v_first ? kValueDim : kKeyDim;
    const int64_t state_dim1 = state_v_first ? kKeyDim : kValueDim;
    if (has_initial)
        check_c16_tensor(initial_state, "initial_state", state_dtype, {N, H, state_dim0, state_dim1});
    if (store_final)
        check_c16_tensor(final_state, "final_state", state_dtype, {N, H, state_dim0, state_dim1});
    for (const auto &tensor : {ws_kdqd, ws_krgt, ws_inv, ws_mqk, beta_sigmoid, out,
                               sequence_info})
        TORCH_CHECK(tensor.device() == v.device(),
                    "C16 K2 varlen tensors must share a device");
    if (has_initial)
        TORCH_CHECK(initial_state.device() == v.device(),
                    "initial_state must share a device");
    if (store_final)
        TORCH_CHECK(final_state.device() == v.device(), "final_state must share a device");
    const auto stream = at::hip::getCurrentHIPStream(v.get_device());
    flash_kda::detail::ForwardParams params;
    params.batch = 1;
    params.tokens = T;
    params.heads = H;
    params.sequence_count = N;
    params.head_stride_chunks = Qcap;
    params.workspace_chunks = P;
    params.is_varlen = true;
    params.has_initial = has_initial;
    params.store_final = store_final;
    params.state_bf16 = state_dtype == at::kBFloat16;
    params.state_v_first = state_v_first;
    params.v = v.data_ptr();
    params.out = out.data_ptr();
    params.initial_state = has_initial ? initial_state.data_ptr() : nullptr;
    params.final_state = store_final ? final_state.data_ptr() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kdqd.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_krgt.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv.data_ptr());
    views.mqk = reinterpret_cast<unsigned short *>(ws_mqk.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();
    views.sequence_info = reinterpret_cast<int64_t *>(sequence_info.data_ptr());

    flash_kda::detail::launch_k2(params, views, stream);
    TORCH_CHECK(hipGetLastError() == hipSuccess, "C16 K2 varlen launch failed");
}

// ===========================================================================
// raw launch：定长与 packed 变长合一，只做模板选择与启动
// ===========================================================================
namespace flash_kda
{
    namespace detail
    {

        void launch_k2(const ForwardParams &params, const WorkspaceViews &views,
                       hipStream_t stream)
        {
            const unsigned int columns = kValueDim / (kK2VSlice * kK2Waves);
            const auto launch = [&](auto state_bf16_tag, auto full_tag, auto state_v_first_tag)
            {
                constexpr bool StateBf16 = decltype(state_bf16_tag)::value;
                constexpr bool FullChunks = decltype(full_tag)::value;
                constexpr bool StateVFirst = decltype(state_v_first_tag)::value;
                if(params.is_varlen)
                {
                    hipLaunchKernelGGL(
                        (kda_k2_kernel</*FullChunks=*/false, StateBf16, /*IsVarlen=*/true,
                                       StateVFirst>),
                        dim3(columns, static_cast<unsigned int>(params.sequence_count * params.heads)),
                        dim3(kK2Waves * 64), 0, stream,
                        reinterpret_cast<const u16 *>(views.kdqd),
                        reinterpret_cast<const u16 *>(views.krgt),
                        reinterpret_cast<const u16 *>(views.inv),
                        reinterpret_cast<const u16 *>(views.mqk),
                        reinterpret_cast<const u16 *>(params.v),
                        views.beta_sigmoid,
                        reinterpret_cast<u16 *>(params.out),
                        params.has_initial
                            ? reinterpret_cast<const state_scalar_t<StateBf16> *>(params.initial_state)
                            : nullptr,
                        params.store_final
                            ? reinterpret_cast<state_scalar_t<StateBf16> *>(params.final_state)
                            : nullptr,
                        static_cast<int>(params.sequence_count), static_cast<int>(params.heads),
                        static_cast<int>(params.tokens), static_cast<int>(params.head_stride_chunks),
                        params.has_initial, params.store_final, views.sequence_info);
                }
                else
                {
                    hipLaunchKernelGGL(
                        (kda_k2_kernel<FullChunks, StateBf16, /*IsVarlen=*/false, StateVFirst>),
                        dim3(columns, static_cast<unsigned int>(params.batch * params.heads)),
                        dim3(kK2Waves * 64), 0, stream,
                        reinterpret_cast<const u16 *>(views.kdqd),
                        reinterpret_cast<const u16 *>(views.krgt),
                        reinterpret_cast<const u16 *>(views.inv),
                        reinterpret_cast<const u16 *>(views.mqk),
                        reinterpret_cast<const u16 *>(params.v),
                        views.beta_sigmoid,
                        reinterpret_cast<u16 *>(params.out),
                        params.has_initial
                            ? reinterpret_cast<const state_scalar_t<StateBf16> *>(params.initial_state)
                            : nullptr,
                        params.store_final
                            ? reinterpret_cast<state_scalar_t<StateBf16> *>(params.final_state)
                            : nullptr,
                        static_cast<int>(params.batch), static_cast<int>(params.heads),
                        static_cast<int>(params.tokens), static_cast<int>(params.head_stride_chunks),
                        params.has_initial, params.store_final, nullptr);
                }
            };
            const bool full_chunks = !params.is_varlen && (params.tokens % kChunkSize) == 0;
            // 三个真实输入差异各自独立：外部 state dtype、满块/尾块、外部 state 布局。
            // 禁止用一个开关同时改布局与 dtype，否则 A/B 无法归因。
            const auto launch_layout = [&](auto state_bf16_tag)
            {
                if(full_chunks)
                    params.state_v_first
                        ? launch(state_bf16_tag, std::true_type{}, std::true_type{})
                        : launch(state_bf16_tag, std::true_type{}, std::false_type{});
                else
                    params.state_v_first
                        ? launch(state_bf16_tag, std::false_type{}, std::true_type{})
                        : launch(state_bf16_tag, std::false_type{}, std::false_type{});
            };
            params.state_bf16 ? launch_layout(std::true_type{})
                              : launch_layout(std::false_type{});
        }

    } // namespace detail
} // namespace flash_kda
