// SPDX-License-Identifier: MIT
// Copyright (C) 2025-2026, Advanced Micro Devices, Inc. All rights reserved.

#include "fused_ar_mhc_post.h"
#include "custom_all_reduce.cuh"
#include "mhc.h"
#include <c10/core/StreamGuard.h>
#include <c10/hip/HIPStream.h>
#include "aiter_enum.h"
#include "aiter_hip_common.h"
#include "aiter_stream.h"

namespace aiter {

// Reuse the Hygon MHC post dispatcher (including its architecture tuning).
// These tensor views own no memory; the caller retains all buffers through
// stream completion. The stream guard preserves AITER's explicit stream ABI.
void launch_mhc_post_raw(hipStream_t stream, AiterDtype dtype, void* out_ptr,
                        void* x_ptr, void* residual_ptr, void* post_ptr, void* comb_ptr,
                        int m, int hidden, int x_stride, int residual_stride)
{
    int device; HIP_CALL(hipGetDevice(&device));
    c10::StreamGuard guard(c10::hip::getStreamFromExternal(stream, device));
    auto options = torch::TensorOptions().device(torch::kCUDA, device)
        .dtype(dtype == AITER_DTYPE_bf16 ? torch::kBFloat16 : torch::kFloat16);
    auto out = torch::from_blob(out_ptr, {m, 4, hidden}, {residual_stride, hidden, 1}, options);
    auto x = torch::from_blob(x_ptr, {m, hidden}, {x_stride, 1}, options);
    auto residual = torch::from_blob(residual_ptr, {m, 4, hidden}, {residual_stride, hidden, 1}, options);
    auto post = torch::from_blob(post_ptr, {m, 4}, options.dtype(torch::kFloat32));
    auto comb = torch::from_blob(comb_ptr, {m, 4, 4}, options.dtype(torch::kFloat32));
    mhc_post(out, x, residual, post, comb);
}

namespace {

void validate_ar_mhc(fptr_t handle, const aiter_tensor_t& inp,
                     const aiter_tensor_t& out, const aiter_tensor_t& residual,
                     const aiter_tensor_t& post, const aiter_tensor_t& comb,
                     bool open_fp8_quant, int64_t reg_ptr, int64_t reg_bytes)
{
    if(!handle || !inp.is_gpu() || inp.dim() != 2 || inp.numel() == 0 ||
       (inp.dtype() != AITER_DTYPE_fp16 && inp.dtype() != AITER_DTYPE_bf16))
        throw std::invalid_argument("AR MHC requires nonempty 2D FP16/BF16 input and a communicator");
    auto fa = reinterpret_cast<CustomAllreduce*>(handle);
    if(fa->world_size_ != 2 && fa->world_size_ != 4 && fa->world_size_ != 8)
        throw std::invalid_argument("AR MHC supports TP2/4/8");
    for(const auto* t : {&inp, &out, &residual, &post, &comb})
        if(!t->is_contiguous() || t->device_id != inp.device_id)
            throw std::invalid_argument("AR MHC requires contiguous tensors on one device");
    if(out.dtype() != inp.dtype() || residual.dtype() != inp.dtype() ||
       post.dtype() != AITER_DTYPE_fp32 || comb.dtype() != AITER_DTYPE_fp32 ||
       residual.dim() != 3 || out.dim() != 3 || post.dim() != 2 || comb.dim() != 3 ||
       residual.size(0) != inp.size(0) || residual.size(1) != 4 || residual.size(2) != inp.size(1) ||
       out.size(0) != inp.size(0) || out.size(1) != 4 || out.size(2) != inp.size(1) ||
       post.size(0) != inp.size(0) || post.size(1) != 4 ||
       comb.size(0) != inp.size(0) || comb.size(1) != 4 || comb.size(2) != 4)
        throw std::invalid_argument("invalid AR MHC residual/mixing shape or dtype");
    if(inp.size(1) % 256 || inp.size(1) < 256)
        throw std::invalid_argument("AR MHC hidden width must be a positive multiple of 256");
    if(open_fp8_quant)
        throw std::invalid_argument("AR MHC FP8 quantization is not implemented");
    auto lo = reinterpret_cast<uintptr_t>(out.data_ptr());
    auto hi = lo + out.numel() * out.element_size();
    for(const auto* t : {&inp, &residual, &post, &comb}) {
        auto other = reinterpret_cast<uintptr_t>(t->data_ptr());
        if(lo < other + t->numel() * t->element_size() && other < hi)
            throw std::invalid_argument("AR MHC output must not alias its inputs");
    }
#ifdef DTK_ENV
    if(!reg_ptr) throw std::invalid_argument("DTK AR MHC requires the communicator copy-in buffer");
#endif
    if(reg_ptr && (reg_bytes < 0 || inp.numel() * inp.element_size() > size_t(reg_bytes)))
        throw std::invalid_argument("AR MHC copy-in buffer is too small");
}


void copy_input_to_registered_buffer(const aiter_tensor_t& inp,
                                     int m,
                                     int input_n,
                                     hipStream_t stream,
                                     int64_t reg_ptr,
                                     int64_t reg_bytes)
{
    int64_t data_bytes = inp.numel() * inp.element_size();
    if(reg_ptr == 0)
        return;
    if(data_bytes > reg_bytes)
        throw std::runtime_error("registered buffer is too small to contain the input");
    HIP_CALL(hipMemcpyAsync((void*)reg_ptr, inp.data_ptr(), data_bytes,
                            hipMemcpyDeviceToDevice, stream));
}

template <typename T>
AiterDtype aiter_dtype_for_ar_mhc_post()
{
    if constexpr(std::is_same_v<T, opus::bf16_t>)
        return AITER_DTYPE_bf16;
    else
        return AITER_DTYPE_fp16;
}

template <typename T>
void run_ar_mhc_post_split(CustomAllreduce* fa,
                           hipStream_t stream,
                           AiterDtype dtype,
                           T* inp_ptr,
                           T* next_residual_ptr,
                           T* residual_ptr,
                           float* post_layer_mix_ptr,
                           float* comb_res_mix_ptr,
                           int m,
                           int input_n,
                           int hidden_size,
                           int residual_stride,
                           int64_t reg_ptr,
                           int64_t reg_bytes);

template <typename T>
void run_ar_mhc_post_large_m(CustomAllreduce* fa,
                             hipStream_t stream,
                             T* inp_ptr,
                             T* next_residual_ptr,
                             T* residual_ptr,
                             float* post_layer_mix_ptr,
                             float* comb_res_mix_ptr,
                             int m,
                             int input_n,
                             int hidden_size,
                             int residual_stride,
                             int64_t reg_ptr,
                             int64_t reg_bytes)
{
    const int64_t size_bytes = static_cast<int64_t>(m) * input_n * static_cast<int64_t>(sizeof(T));
    constexpr int64_t kSplitMinBytes = 512 * 1024;
    if(fa->world_size_ >= 4 && size_bytes > kSplitMinBytes)
    {
        run_ar_mhc_post_split(fa,
                              stream,
                              aiter_dtype_for_ar_mhc_post<T>(),
                              inp_ptr,
                              next_residual_ptr,
                              residual_ptr,
                              post_layer_mix_ptr,
                              comb_res_mix_ptr,
                              m,
                              input_n,
                              hidden_size,
                              residual_stride,
                              reg_ptr,
                              reg_bytes);
        return;
    }

    void* actual_inp = inp_ptr;
    if(reg_ptr != 0)
        actual_inp = (void*)reg_ptr;
    fa->dispatchAllReduceMhcPost1Stage<T>(stream,
                                          reinterpret_cast<T*>(actual_inp),
                                          next_residual_ptr,
                                          residual_ptr,
                                          post_layer_mix_ptr,
                                          comb_res_mix_ptr,
                                          m,
                                          input_n,
                                          hidden_size,
                                          residual_stride);
}

template <typename T>
void run_ar_mhc_post_split(CustomAllreduce* fa,
                           hipStream_t stream,
                           AiterDtype dtype,
                           T* inp_ptr,
                           T* next_residual_ptr,
                           T* residual_ptr,
                           float* post_layer_mix_ptr,
                           float* comb_res_mix_ptr,
                           int m,
                           int input_n,
                           int hidden_size,
                           int residual_stride,
                           int64_t reg_ptr,
                           int64_t reg_bytes)
{
    void* actual_inp = inp_ptr;
    if(reg_ptr != 0)
        actual_inp = (void*)reg_ptr;
    fa->dispatchAllReduceMhcPostSplit<T>(stream,
                                         reinterpret_cast<T*>(actual_inp),
                                         next_residual_ptr,
                                         residual_ptr,
                                         post_layer_mix_ptr,
                                         comb_res_mix_ptr,
                                         m,
                                         input_n,
                                         hidden_size,
                                         residual_stride);
    launch_mhc_post_raw(stream,
                        dtype,
                        next_residual_ptr,
                        fa->local_tmp_reduced_ptr<T>(),
                        residual_ptr,
                        post_layer_mix_ptr,
                        comb_res_mix_ptr,
                        m,
                        hidden_size,
                        hidden_size,
                        residual_stride);
}

template <typename T>
void run_ar_mhc_post_1stage(CustomAllreduce* fa,
                            hipStream_t stream,
                            T* inp_ptr,
                            T* next_residual_ptr,
                            T* residual_ptr,
                            float* post_layer_mix_ptr,
                            float* comb_res_mix_ptr,
                            int m,
                            int input_n,
                            int hidden_size,
                            int residual_stride,
                            int64_t reg_ptr,
                            int64_t reg_bytes)
{
    void* actual_inp = inp_ptr;
    if(reg_ptr != 0)
        actual_inp = (void*)reg_ptr;
    fa->dispatchAllReduceMhcPost1Stage<T>(stream,
                                          reinterpret_cast<T*>(actual_inp),
                                          next_residual_ptr,
                                          residual_ptr,
                                          post_layer_mix_ptr,
                                          comb_res_mix_ptr,
                                          m,
                                          input_n,
                                          hidden_size,
                                          residual_stride);
}

} // namespace

void fused_allreduce_mhc_post_only(fptr_t _fa,
                                   aiter_tensor_t& inp,
                                   aiter_tensor_t& next_residual,
                                   aiter_tensor_t& residual_in,
                                   aiter_tensor_t& post_layer_mix,
                                   aiter_tensor_t& comb_res_mix,
                                   bool use_new,
                                   bool open_fp8_quant,
                                   int64_t reg_ptr,
                                   int64_t reg_bytes)
{
    (void)use_new;
    validate_ar_mhc(_fa, inp, next_residual, residual_in, post_layer_mix,
                    comb_res_mix, open_fp8_quant, reg_ptr, reg_bytes);
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa            = reinterpret_cast<CustomAllreduce*>(_fa);

    const int m       = static_cast<int>(inp.numel() / inp.size(-1));
    const int input_n = static_cast<int>(inp.size(-1));
    const int hidden  = static_cast<int>(residual_in.size(-1));
    const int stride  = static_cast<int>(residual_in.stride(0));

    copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);

    switch(inp.dtype())
    {
    case AITER_DTYPE_bf16: {
        run_ar_mhc_post_large_m<opus::bf16_t>(
            fa,
            stream,
            reinterpret_cast<opus::bf16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    case AITER_DTYPE_fp16: {
        run_ar_mhc_post_large_m<opus::fp16_t>(
            fa,
            stream,
            reinterpret_cast<opus::fp16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    default:
        throw std::runtime_error("fused AR+MHC post only supports fp16/bf16 activations");
    }
}

void fused_allreduce_mhc_post_one_stage(fptr_t _fa,
                                        aiter_tensor_t& inp,
                                        aiter_tensor_t& next_residual,
                                        aiter_tensor_t& residual_in,
                                        aiter_tensor_t& post_layer_mix,
                                        aiter_tensor_t& comb_res_mix,
                                        bool use_new,
                                        bool open_fp8_quant,
                                        int64_t reg_ptr,
                                        int64_t reg_bytes)
{
    (void)use_new;
    validate_ar_mhc(_fa, inp, next_residual, residual_in, post_layer_mix,
                    comb_res_mix, open_fp8_quant, reg_ptr, reg_bytes);
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa            = reinterpret_cast<CustomAllreduce*>(_fa);

    const int m       = static_cast<int>(inp.numel() / inp.size(-1));
    const int input_n = static_cast<int>(inp.size(-1));
    const int hidden  = static_cast<int>(residual_in.size(-1));
    const int stride  = static_cast<int>(residual_in.stride(0));

    copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);

    switch(inp.dtype())
    {
    case AITER_DTYPE_bf16: {
        run_ar_mhc_post_1stage<opus::bf16_t>(
            fa,
            stream,
            reinterpret_cast<opus::bf16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    case AITER_DTYPE_fp16: {
        run_ar_mhc_post_1stage<opus::fp16_t>(
            fa,
            stream,
            reinterpret_cast<opus::fp16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    default:
        throw std::runtime_error("fused AR+MHC post one-stage supports fp16/bf16 activations");
    }
}

void fused_allreduce_mhc_post_split(fptr_t _fa,
                                    aiter_tensor_t& inp,
                                    aiter_tensor_t& next_residual,
                                    aiter_tensor_t& residual_in,
                                    aiter_tensor_t& post_layer_mix,
                                    aiter_tensor_t& comb_res_mix,
                                    bool use_new,
                                    bool open_fp8_quant,
                                    int64_t reg_ptr,
                                    int64_t reg_bytes)
{
    (void)use_new;
    validate_ar_mhc(_fa, inp, next_residual, residual_in, post_layer_mix,
                    comb_res_mix, open_fp8_quant, reg_ptr, reg_bytes);
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa            = reinterpret_cast<CustomAllreduce*>(_fa);

    const int m       = static_cast<int>(inp.numel() / inp.size(-1));
    const int input_n = static_cast<int>(inp.size(-1));
    const int hidden  = static_cast<int>(residual_in.size(-1));
    const int stride  = static_cast<int>(residual_in.stride(0));

    copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);

    switch(inp.dtype())
    {
    case AITER_DTYPE_bf16: {
        run_ar_mhc_post_split<opus::bf16_t>(
            fa,
            stream,
            AITER_DTYPE_bf16,
            reinterpret_cast<opus::bf16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    case AITER_DTYPE_fp16: {
        run_ar_mhc_post_split<opus::fp16_t>(
            fa,
            stream,
            AITER_DTYPE_fp16,
            reinterpret_cast<opus::fp16_t*>(inp.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(next_residual.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(residual_in.data_ptr()),
            reinterpret_cast<float*>(post_layer_mix.data_ptr()),
            reinterpret_cast<float*>(comb_res_mix.data_ptr()),
            m,
            input_n,
            hidden,
            stride,
            reg_ptr,
            reg_bytes);
        break;
    }
    default:
        throw std::runtime_error("fused AR+MHC post split supports fp16/bf16 activations");
    }
}

} // namespace aiter
