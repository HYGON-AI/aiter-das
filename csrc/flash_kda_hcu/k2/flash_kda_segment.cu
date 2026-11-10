#include "flash_kda_launch.h"
// SPDX-License-Identifier: MIT
//
// 分段 K2 的主机入口：affine pass → 段间 scan → replay。

#include <ATen/hip/HIPContext.h>
#include <torch/extension.h>

#include <initializer_list>
#include <type_traits>
#include <vector>

#include "flash_kda_hcu.h"
#include "flash_kda_segment_pass.cuh"
#include "flash_kda_segment_replay.cuh"
#include "flash_kda_segment_scan.cuh"

void kda_segment_scan_forward(
    const torch::Tensor &segment_transition,
    const torch::Tensor &segment_update,
    torch::Tensor &segment_initial_states,
    const torch::Tensor &initial_state,
    int segment_count,
    bool state_v_first)
{
    TORCH_CHECK(segment_transition.dim() == 5 && segment_update.dim() == 5 && segment_initial_states.dim() == 5,
                "C16 segment buffers must have shape [S,B,H,128,128]");
    const int sequence_count = static_cast<int>(segment_transition.size(1));
    const int heads = static_cast<int>(segment_transition.size(2));
    TORCH_CHECK(segment_transition.size(0) == segment_count && segment_transition.size(3) == kKeyDim &&
                    segment_transition.size(4) == kValueDim,
                "C16 segment_transition shape is unsupported");
    check_k2_tensor(segment_transition, "C16 segment_transition", at::kBFloat16,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    check_k2_tensor(segment_update, "C16 segment_update", at::kFloat,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    check_k2_tensor(segment_initial_states, "C16 segment_initial_states", at::kFloat,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    const bool has_initial = initial_state.defined() && initial_state.numel() > 0;
    const at::ScalarType initial_state_dtype =
        has_initial ? initial_state.scalar_type() : at::kFloat;
    TORCH_CHECK(initial_state_dtype == at::kFloat ||
                    initial_state_dtype == at::kBFloat16,
                "C16 initial_state must be FP32 or BF16");
    if (has_initial)
        check_k2_tensor(initial_state, "C16 initial_state", initial_state_dtype,
                        {sequence_count, heads,
                         state_v_first ? kValueDim : kKeyDim,
                         state_v_first ? kKeyDim : kValueDim});
    for (const auto &tensor : {segment_transition, segment_update, segment_initial_states})
        TORCH_CHECK(tensor.device() == segment_transition.device(),
                    "C16 segment buffers must share a device");
    if (has_initial)
        TORCH_CHECK(initial_state.device() == segment_transition.device(),
                    "C16 initial_state must share a device");

    flash_kda::detail::ForwardParams params;
    params.batch = sequence_count;
    params.tokens = 0;  // scan 不使用 token 数
    params.heads = heads;
    params.sequence_count = sequence_count;
    params.segment_count = segment_count;
    params.has_initial = has_initial;
    params.state_bf16 = initial_state_dtype == at::kBFloat16;
    params.state_v_first = state_v_first;
    params.initial_state = has_initial ? initial_state.data_ptr() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.segment_transition = segment_transition.data_ptr();
    views.segment_update = segment_update.data_ptr();
    views.segment_initial_states = segment_initial_states.data_ptr();

    flash_kda::detail::launch_segment_scan(
        params, views, at::hip::getCurrentHIPStream(segment_transition.get_device()));
    TORCH_CHECK(hipGetLastError() == hipSuccess, "C16 kda_segment_scan_kernel launch failed");
}

void kda_segment_affine_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &segment_update,
    torch::Tensor &segment_transition,
    int segment_count,
    int chunks_per_segment)
{
    TORCH_CHECK(ws_kdqd.dim() == 5, "C16 ws_kdqd must have shape [P,2,8,16,16]");
    const int64_t p_count = ws_kdqd.size(0);
    TORCH_CHECK(p_count > 0, "C16 workspace P must be positive");
    check_k2_tensor(ws_kdqd, "C16 ws_kdqd", at::kBFloat16, {p_count, 2, 8, 16, 16});
    // kr 与 gt 是同一块 [P,9,16,16] bf16（gt 段 = 第 9 个 tile）
    check_k2_tensor(ws_krgt, "C16 ws_krgt", at::kBFloat16, {p_count, 9, 16, 16});
    check_k2_tensor(ws_inv, "C16 ws_inv", at::kBFloat16, {p_count, 1, 1, 16, 16});
    TORCH_CHECK(v.dim() == 4, "C16 v must have shape [B,T,H,128]");
    const int sequence_count = static_cast<int>(v.size(0));
    const int input_token_count = static_cast<int>(v.size(1));
    const int heads = static_cast<int>(v.size(2));
    check_k2_tensor(v, "C16 v", at::kBFloat16, {sequence_count, input_token_count, heads, kValueDim});
    TORCH_CHECK(segment_count > 0 && chunks_per_segment > 0,
                "C16 segment_count and chunks_per_segment must be positive");
    check_k2_tensor(segment_update, "C16 segment_update", at::kFloat,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    check_k2_tensor(segment_transition, "C16 segment_transition", at::kBFloat16,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    // 四 wave 内核只实现 beta_sigmoid 预激活路径 ⇒ 它是必需输入，不再保留"可选→稍后要求必有"。
    check_k2_tensor(beta_sigmoid, "C16 beta_sigmoid", at::kFloat, {p_count, kChunkSize});
    const int64_t chunk_count = (input_token_count + kChunkSize - 1) / kChunkSize;
    TORCH_CHECK(p_count == static_cast<int64_t>(heads) * sequence_count * chunk_count,
                "C16 workspace P does not match [B,T,H] chunk indexing");
    for (const auto &tensor : {ws_kdqd, ws_krgt, ws_inv, v, segment_update,
                              segment_transition, beta_sigmoid})
        TORCH_CHECK(tensor.device() == ws_kdqd.device(),
                    "C16 segment tensors must use the same device");
    TORCH_CHECK(beta_sigmoid.device() == ws_kdqd.device(),
                "C16 beta_sigmoid must share a device");

    flash_kda::detail::ForwardParams params;
    params.batch = sequence_count;
    params.tokens = input_token_count;
    params.heads = heads;
    params.sequence_count = sequence_count;
    params.head_stride_chunks = sequence_count * static_cast<int64_t>(chunk_count);
    params.chunks_per_segment = chunks_per_segment;
    params.segment_count = segment_count;
    params.v = v.data_ptr();

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kdqd.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_krgt.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();
    views.segment_transition = segment_transition.data_ptr();
    views.segment_update = segment_update.data_ptr();

    flash_kda::detail::launch_segment_affine(
        params, views, at::hip::getCurrentHIPStream(ws_kdqd.get_device()));
    TORCH_CHECK(hipGetLastError() == hipSuccess, "C16 kda_passA_c16_4w launch failed");
}

void kda_segment_replay_forward(
    const torch::Tensor &ws_kdqd,
    const torch::Tensor &ws_krgt,
    const torch::Tensor &ws_inv,
    const torch::Tensor &ws_mqk,
    const torch::Tensor &v,
    const torch::Tensor &beta_sigmoid,
    torch::Tensor &out,
    torch::Tensor &final_state,
    const torch::Tensor &segment_initial_states,
    int segment_count,
    int chunks_per_segment,
    bool state_v_first)
{
    TORCH_CHECK(ws_kdqd.dim() == 5, "C16 ws_kdqd must have shape [P,2,8,16,16]");
    const int64_t p_count = ws_kdqd.size(0);
    TORCH_CHECK(p_count > 0, "C16 workspace P must be positive");
    check_k2_tensor(ws_kdqd, "C16 ws_kdqd", at::kBFloat16, {p_count, 2, 8, 16, 16});
    check_k2_tensor(ws_kdqd, "C16 ws_kdqd", at::kBFloat16, {p_count, 2, 8, 16, 16});
    TORCH_CHECK(ws_kdqd.data_ptr() == ws_kdqd.data_ptr(),
                "C16 KDQD merged layout requires ws_kdqd and ws_kdqd to be the same [P,2,8,16,16] tensor");
    // kr 与 gt 是同一块 [P,9,16,16] bf16（gt 段 = 第 9 个 tile）
    check_k2_tensor(ws_krgt, "C16 ws_krgt", at::kBFloat16, {p_count, 9, 16, 16});
    check_k2_tensor(ws_inv, "C16 ws_inv", at::kBFloat16, {p_count, 1, 1, 16, 16});
    check_k2_tensor(ws_mqk, "C16 ws_mqk", at::kBFloat16, {p_count, 1, 1, 16, 16});
    TORCH_CHECK(v.dim() == 4, "C16 v must have shape [B,T,H,128]");
    const int sequence_count = static_cast<int>(v.size(0));
    const int input_token_count = static_cast<int>(v.size(1));
    const int heads = static_cast<int>(v.size(2));
    check_k2_tensor(v, "C16 v", at::kBFloat16, {sequence_count, input_token_count, heads, kValueDim});
    check_k2_tensor(out, "C16 out", at::kBFloat16, {sequence_count, input_token_count, heads, kValueDim});
    TORCH_CHECK(segment_count > 0 && chunks_per_segment > 0,
                "C16 segment_count and chunks_per_segment must be positive");
    check_k2_tensor(segment_initial_states, "C16 segment_initial_states", at::kFloat,
                    {segment_count, sequence_count, heads, kKeyDim, kValueDim});
    // 四 wave 内核只实现 beta_sigmoid 预激活路径 ⇒ 它是必需输入，不再保留"可选→稍后要求必有"。
    check_k2_tensor(beta_sigmoid, "C16 beta_sigmoid", at::kFloat, {p_count, kChunkSize});
    const bool store_final = final_state.defined() && final_state.numel() > 0;
    const at::ScalarType final_state_dtype =
        store_final ? final_state.scalar_type() : at::kFloat;
    TORCH_CHECK(final_state_dtype == at::kFloat ||
                    final_state_dtype == at::kBFloat16,
                "C16 final_state must be FP32 or BF16");
    if (store_final)
        check_k2_tensor(final_state, "C16 final_state", final_state_dtype,
                        {sequence_count, heads,
                         state_v_first ? kValueDim : kKeyDim,
                         state_v_first ? kKeyDim : kValueDim});
    const int64_t chunk_count = (input_token_count + kChunkSize - 1) / kChunkSize;
    TORCH_CHECK(p_count == static_cast<int64_t>(heads) * sequence_count * chunk_count,
                "C16 workspace P does not match [B,T,H] chunk indexing");
    for (const auto &tensor : {ws_kdqd, ws_krgt, ws_inv, ws_mqk, v, out,
                               segment_initial_states, beta_sigmoid})
        TORCH_CHECK(tensor.device() == ws_kdqd.device(),
                    "C16 replay tensors must use the same device");
    TORCH_CHECK(beta_sigmoid.device() == ws_kdqd.device(),
                "C16 beta_sigmoid must share a device");
    if (store_final)
        TORCH_CHECK(final_state.device() == ws_kdqd.device(),
                    "C16 final_state must share a device");

    flash_kda::detail::ForwardParams params;
    params.batch = sequence_count;
    params.tokens = input_token_count;
    params.heads = heads;
    params.sequence_count = sequence_count;
    params.head_stride_chunks = sequence_count * static_cast<int64_t>(chunk_count);
    params.chunks_per_segment = chunks_per_segment;
    params.segment_count = segment_count;
    params.store_final = store_final;
    params.state_bf16 = final_state_dtype == at::kBFloat16;
    params.state_v_first = state_v_first;
    params.v = v.data_ptr();
    params.out = out.data_ptr();
    params.final_state = store_final ? final_state.data_ptr() : nullptr;

    flash_kda::detail::WorkspaceViews views;
    views.kdqd = reinterpret_cast<unsigned short *>(ws_kdqd.data_ptr());
    views.krgt = reinterpret_cast<unsigned short *>(ws_krgt.data_ptr());
    views.inv = reinterpret_cast<unsigned short *>(ws_inv.data_ptr());
    views.mqk = reinterpret_cast<unsigned short *>(ws_mqk.data_ptr());
    views.beta_sigmoid = beta_sigmoid.data_ptr<float>();
    views.segment_initial_states = segment_initial_states.data_ptr();

    flash_kda::detail::launch_segment_replay(
        params, views, at::hip::getCurrentHIPStream(ws_kdqd.get_device()));
    TORCH_CHECK(hipGetLastError() == hipSuccess, "C16 kda_replay_c16_4w launch failed");
}

// ===========================================================================
// raw launch：三个分段阶段只做模板选择与启动
// ===========================================================================
namespace flash_kda
{
    namespace detail
    {

        void launch_segment_scan(const ForwardParams &params, const WorkspaceViews &views,
                                 hipStream_t stream)
        {
            const dim3 grid(params.sequence_count * params.heads,
                            (kValueDim / 16 + kSegmentScanWaves - 1) / kSegmentScanWaves);
            const dim3 block(kSegmentScanWaves * 64);
            const auto launch = [&](auto state_tag, auto layout_tag)
            {
                constexpr bool StateBf16 = decltype(state_tag)::value;
                constexpr bool StateVFirst = decltype(layout_tag)::value;
                hipLaunchKernelGGL(
                    (kda_segment_scan_kernel<StateBf16, StateVFirst>), grid, block, 0, stream,
                    reinterpret_cast<const unsigned short *>(views.segment_transition),
                    reinterpret_cast<const float *>(views.segment_update),
                    reinterpret_cast<float *>(views.segment_initial_states),
                    params.has_initial
                        ? reinterpret_cast<const state_scalar_t<StateBf16> *>(params.initial_state)
                        : nullptr,
                    static_cast<int>(params.sequence_count), static_cast<int>(params.heads),
                    static_cast<int>(params.segment_count), params.has_initial);
            };
            const auto launch_layout = [&](auto state_tag)
            {
                params.state_v_first ? launch(state_tag, std::true_type{})
                                     : launch(state_tag, std::false_type{});
            };
            params.state_bf16 ? launch_layout(std::true_type{}) : launch_layout(std::false_type{});
        }

        void launch_segment_affine(const ForwardParams &params, const WorkspaceViews &views,
                                   hipStream_t stream)
        {
            const dim3 grid4w((kValueDim / 16 + 3) / 4,
                              static_cast<unsigned int>(params.segment_count * params.sequence_count *
                                                        params.heads));
            hipLaunchKernelGGL(
                (kda_passA_c16_4w), grid4w, dim3(256), 0, stream,
                reinterpret_cast<const unsigned short *>(views.kdqd),
                reinterpret_cast<const unsigned short *>(views.krgt),
                reinterpret_cast<const unsigned short *>(views.inv),
                reinterpret_cast<const unsigned short *>(params.v),
                views.beta_sigmoid,
                reinterpret_cast<float *>(views.segment_update),
                reinterpret_cast<unsigned short *>(views.segment_transition),
                static_cast<int>(params.sequence_count), static_cast<int>(params.heads),
                static_cast<int>(params.tokens), static_cast<int>(params.head_stride_chunks),
                static_cast<int>(params.segment_count),
                static_cast<int>(params.chunks_per_segment));
        }

        void launch_segment_replay(const ForwardParams &params, const WorkspaceViews &views,
                                   hipStream_t stream)
        {
            const dim3 grid4w((kValueDim / 16 + 3) / 4,
                              static_cast<unsigned int>(params.segment_count * params.sequence_count *
                                                        params.heads));
            const auto launch4w = [&](auto state_tag, auto layout_tag)
            {
                constexpr bool StateBf16 = decltype(state_tag)::value;
                constexpr bool StateVFirst = decltype(layout_tag)::value;
                hipLaunchKernelGGL(
                    (kda_replay_c16_4w<StateBf16, StateVFirst>), grid4w, dim3(256), 0, stream,
                    reinterpret_cast<const unsigned short *>(views.kdqd),
                    reinterpret_cast<const unsigned short *>(views.krgt),
                    reinterpret_cast<const unsigned short *>(views.inv),
                    reinterpret_cast<const unsigned short *>(views.mqk),
                    reinterpret_cast<const unsigned short *>(params.v),
                    views.beta_sigmoid,
                    reinterpret_cast<unsigned short *>(params.out),
                    params.store_final
                        ? reinterpret_cast<state_scalar_t<StateBf16> *>(params.final_state)
                        : nullptr,
                    reinterpret_cast<const float *>(views.segment_initial_states),
                    static_cast<int>(params.sequence_count), static_cast<int>(params.heads),
                    static_cast<int>(params.tokens), static_cast<int>(params.head_stride_chunks),
                    static_cast<int>(params.segment_count),
                    static_cast<int>(params.chunks_per_segment), params.store_final);
            };
            const auto launch_layout = [&](auto state_tag)
            {
                params.state_v_first ? launch4w(state_tag, std::true_type{})
                                     : launch4w(state_tag, std::false_type{});
            };
            params.state_bf16 ? launch_layout(std::true_type{}) : launch_layout(std::false_type{});
        }

    } // namespace detail
} // namespace flash_kda
