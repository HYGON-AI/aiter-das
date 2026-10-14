// Modified by Hygon Information Technology Co., Ltd. for Hygon GPU support.
/*
 * Copyright © Advanced Micro Devices, Inc. All rights reserved.
 * Copyright (C) 2024-2026, The vLLM team.
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
#include "custom_all_reduce.cuh"
#include "aiter_stream.h"
#include "aiter_tensor.h"
#include <cstring>

using fp8_type = opus::fp8_t;

// fake pointer type, must match fptr_t type in custom_all_reduce.h
using fptr_t = int64_t;
static_assert(sizeof(void*) == sizeof(fptr_t));

namespace aiter {

bool ag_rs_requires_copy_in()
{
    // DTK 26.04 on gfx936/gfx938 fails changing-input registered-graph
    // replay even with system fences. Keep DTK on the verified copy-in path
    // until a toolchain-specific direct-input closure is available.
#ifdef DTK_ENV
    return true;
#else
    return false;
#endif
}

// ---- init / dispose / meta_size ----

fptr_t init_custom_ar(int64_t meta_ptr,
                      int64_t rank_data_ptr,
                      int64_t rank_data_sz,
                      const std::vector<int64_t>& ipc_handle_ptrs,
                      const std::vector<int64_t>& offsets,
                      int64_t rank,
                      bool fully_connected,
                      int64_t transport)
{
    int world_size = offsets.size();
    if(world_size > kMaxRanks)
        throw std::invalid_argument("world size > " + std::to_string(kMaxRanks) +
                                    " is not supported");
    if(world_size % 2 != 0)
        throw std::invalid_argument("Odd num gpus is not supported for now");
    if(world_size != (int)ipc_handle_ptrs.size())
        throw std::invalid_argument("handles length should equal to offsets length");
    if(rank < 0 || rank >= world_size)
        throw std::invalid_argument("invalid rank passed in");
    if(transport != static_cast<int64_t>(ARTransport::IPC) &&
       transport != static_cast<int64_t>(ARTransport::Fabric))
        throw std::invalid_argument("invalid custom allreduce transport");

    std::vector<const void*> handles(world_size);
    for(int i = 0; i < world_size; i++)
        handles[i] = reinterpret_cast<const void*>(ipc_handle_ptrs[i]);
    return (fptr_t) new aiter::CustomAllreduce(reinterpret_cast<aiter::Signal*>(meta_ptr),
                                               (void*)rank_data_ptr,
                                               rank_data_sz,
                                               handles.data(),
                                               offsets,
                                               rank,
                                               fully_connected,
                                               static_cast<ARTransport>(transport));
}

void dispose(fptr_t _fa)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    delete fa;
}

int64_t meta_size() { return sizeof(aiter::Signal); }

int64_t small_ar_scratch_size(int64_t world_size)
{
    if(world_size != 2 && world_size != 4 && world_size != 8) return 0;
    return hcu_ll_scratch_bytes(world_size);
}

void configure_small_ar(fptr_t ptr, int64_t max_size, int64_t meta_bytes, int64_t mode)
{
    if(max_size < 0 || meta_bytes < 0 || mode < 0 || mode > 3)
        throw std::invalid_argument("invalid small-message configuration");
    reinterpret_cast<CustomAllreduce*>(ptr)->configure_small_ar(max_size, meta_bytes, mode);
}

// ---- Internal dispatch helpers ----

static void _all_reduce(fptr_t _fa, void* inp, void* out,
                        int64_t numel, AiterDtype dtype,
                        bool use_new, bool open_fp8_quant, bool is_broadcast_reg_outptr)
{
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    switch(dtype)
    {
    case AITER_DTYPE_fp32: {
        fa->allreduce<opus::fp32_t>(stream,
                             reinterpret_cast<opus::fp32_t*>(inp),
                             reinterpret_cast<opus::fp32_t*>(out),
                             numel, use_new, is_broadcast_reg_outptr);
        break;
    }
    case AITER_DTYPE_fp16: {
        if(open_fp8_quant && numel >= 128 * 2048)
        {
            fa->runFp8QuantKernel<opus::fp16_t>(stream,
                                        reinterpret_cast<opus::fp16_t*>(inp),
                                        reinterpret_cast<opus::fp16_t*>(out),
                                        numel);
        }
        else
        {
            fa->allreduce<opus::fp16_t>(stream,
                                reinterpret_cast<opus::fp16_t*>(inp),
                                reinterpret_cast<opus::fp16_t*>(out),
                                numel, use_new, is_broadcast_reg_outptr);
        }
        break;
    }
#if (__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        // Keep the historical BF16 output-registration contract while refusing
        // LL for direct registered inputs, just as for the other dtypes.
        fa->allreduce<opus::bf16_t>(stream,
                                      reinterpret_cast<opus::bf16_t*>(inp),
                                      reinterpret_cast<opus::bf16_t*>(out),
                                      numel, use_new, false, 512,
                                      aiter::CustomAllreduce::default_ar_block_limit,
                                      !is_broadcast_reg_outptr);
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allreduce only supports float32, float16 and bfloat16");
    }
}

static void _reduce_scatter(fptr_t _fa, void* inp, void* out,
                            int64_t size, AiterDtype dtype)
{
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    switch(dtype)
    {
    case AITER_DTYPE_fp32: {
        fa->dispatchReduceScatter<opus::fp32_t>(stream,
                                     reinterpret_cast<opus::fp32_t*>(inp),
                                     reinterpret_cast<opus::fp32_t*>(out),
                                     size);
        break;
    }
    case AITER_DTYPE_fp16: {
        fa->dispatchReduceScatter<opus::fp16_t>(stream,
                                    reinterpret_cast<opus::fp16_t*>(inp),
                                    reinterpret_cast<opus::fp16_t*>(out),
                                    size);
        break;
    }
#if (__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        fa->dispatchReduceScatter<opus::bf16_t>(stream,
                                              reinterpret_cast<opus::bf16_t*>(inp),
                                              reinterpret_cast<opus::bf16_t*>(out),
                                              size);
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allreduce only supports float32, float16 and bfloat16");
    }
}

static void _all_gather(fptr_t _fa, void* inp, void* out,
                        int64_t size, AiterDtype dtype,
                        int64_t last_dim_size, int64_t gather_dim)
{
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    switch(dtype)
    {
    case AITER_DTYPE_i8:
    case AITER_DTYPE_u8:
    case AITER_DTYPE_fp8: {
        // AllGather preserves bits; no FP8 conversion or arithmetic is needed.
        fa->dispatchAllGather<opus::u8_t>(stream,
                                        reinterpret_cast<opus::u8_t*>(inp),
                                        reinterpret_cast<opus::u8_t*>(out),
                                        size, last_dim_size, gather_dim);
        break;
    }
    case AITER_DTYPE_fp32: {
        fa->dispatchAllGather<opus::fp32_t>(stream,
                                     reinterpret_cast<opus::fp32_t*>(inp),
                                     reinterpret_cast<opus::fp32_t*>(out),
                                     size, last_dim_size, gather_dim);
        break;
    }
    case AITER_DTYPE_fp16: {
        fa->dispatchAllGather<opus::fp16_t>(stream,
                                    reinterpret_cast<opus::fp16_t*>(inp),
                                    reinterpret_cast<opus::fp16_t*>(out),
                                    size, last_dim_size, gather_dim);
        break;
    }
#if (__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        fa->dispatchAllGather<opus::bf16_t>(stream,
                                    reinterpret_cast<opus::bf16_t*>(inp),
                                    reinterpret_cast<opus::bf16_t*>(out),
                                    size, last_dim_size, gather_dim);
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allgather supports float32, float16, bfloat16 and 8-bit storage");
    }
}

static void _fused_allreduce_rmsnorm(fptr_t _fa,
                                     void* inp, void* residual_inp,
                                     void* residual_out, void* out,
                                     void* scale_out, void* w,
                                     AiterDtype dtype, float eps,
                                     int m, int input_n, int n, int out_n,
                                     bool use_1stage,
                                     bool gemma_norm,
                                     void* bf16_out = nullptr)
{
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    bool use_fp8_per_token_quant = (scale_out != nullptr);

#define DISPATCH_AR_FUSION(DTYPE)                                \
    if(!use_fp8_per_token_quant)                                 \
    {                                                            \
        fa->dispatchFusedAllReduceRMSNorm<DTYPE>(                \
            stream,                                              \
            reinterpret_cast<DTYPE*>(inp),                       \
            reinterpret_cast<DTYPE*>(residual_inp),              \
            reinterpret_cast<DTYPE*>(residual_out),              \
            reinterpret_cast<DTYPE*>(out),                       \
            reinterpret_cast<DTYPE*>(w),                         \
            eps,                                                 \
            m,                                                   \
            input_n,                                             \
            n,                                                   \
            out_n,                                               \
            use_1stage,                                          \
            gemma_norm);                                         \
    }                                                            \
    else                                                         \
    {                                                            \
        if(input_n != n)                                         \
        {                                                        \
            throw std::runtime_error(                            \
                "fused allreduce rmsnorm quant requires input width == weight width"); \
        }                                                        \
        fa->dispatchFusedAllReduceRMSNormQuant<DTYPE, fp8_type>( \
            stream,                                              \
            reinterpret_cast<DTYPE*>(inp),                       \
            reinterpret_cast<DTYPE*>(residual_inp),              \
            reinterpret_cast<DTYPE*>(residual_out),              \
            reinterpret_cast<fp8_type*>(out),                    \
            reinterpret_cast<float*>(scale_out),                 \
            reinterpret_cast<DTYPE*>(w),                         \
            eps,                                                 \
            m,                                                   \
            n,                                                   \
            use_1stage,                                          \
            gemma_norm,                                          \
            reinterpret_cast<DTYPE*>(bf16_out));                 \
    }

    switch(dtype)
    {
    case AITER_DTYPE_fp32: {
        DISPATCH_AR_FUSION(opus::fp32_t)
        break;
    }
    case AITER_DTYPE_fp16: {
        DISPATCH_AR_FUSION(opus::fp16_t)
        break;
    }
#if(__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        DISPATCH_AR_FUSION(opus::bf16_t)
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allreduce only supports float32, float16 and bfloat16");
    }

#undef DISPATCH_AR_FUSION
}

static bool _can_pack_2d_last_dim_slice(const aiter_tensor_t& inp, int m, int n)
{
    return inp.dim() == 2 && inp.size(0) == m && inp.size(-1) == n &&
           inp.stride(-1) == 1 && inp.stride(0) >= n && !inp.is_contiguous();
}

static void _copy_input_to_registered_buffer(const aiter_tensor_t& inp,
                                             int m,
                                             int n,
                                             hipStream_t stream,
                                             int64_t reg_ptr,
                                             int64_t reg_bytes)
{
    int64_t data_bytes = inp.numel() * inp.element_size();
    if(data_bytes > reg_bytes)
        throw std::runtime_error("registered buffer is too small to contain the input");

    if(_can_pack_2d_last_dim_slice(inp, m, n))
    {
        size_t row_bytes = static_cast<size_t>(n) * inp.element_size();
        size_t src_pitch = static_cast<size_t>(inp.stride(0)) * inp.element_size();
        HIP_CALL(hipMemcpy2DAsync((void*)reg_ptr,
                                  row_bytes,
                                  inp.data_ptr(),
                                  src_pitch,
                                  row_bytes,
                                  static_cast<size_t>(m),
                                  hipMemcpyDeviceToDevice,
                                  stream));
        return;
    }

    HIP_CALL(hipMemcpyAsync((void*)reg_ptr,
                            inp.data_ptr(),
                            data_bytes,
                            hipMemcpyDeviceToDevice,
                            stream));
}

// ---- Buffer registration ----

void register_input_buffer(fptr_t _fa,
                           int64_t self_ptr,
                           const std::vector<int64_t>& ipc_handle_ptrs,
                           const std::vector<int64_t>& offsets)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    int world_size = ipc_handle_ptrs.size();
    std::vector<const void*> handles(world_size);
    for(int i = 0; i < world_size; i++)
        handles[i] = reinterpret_cast<const void*>(ipc_handle_ptrs[i]);
    fa->register_input_buffer(handles.data(), offsets.data(), (void*)self_ptr);
}

void register_output_buffer(fptr_t _fa,
                            int64_t self_ptr,
                            const std::vector<int64_t>& ipc_handle_ptrs,
                            const std::vector<int64_t>& offsets)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    int world_size = ipc_handle_ptrs.size();
    std::vector<const void*> handles(world_size);
    for(int i = 0; i < world_size; i++)
        handles[i] = reinterpret_cast<const void*>(ipc_handle_ptrs[i]);
    fa->register_output_buffer(handles.data(), offsets.data(), (void*)self_ptr);
}

int64_t get_graph_buffer_count(fptr_t _fa)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    return (int64_t)(fa->graph_unreg_input_buffers_.size() +
                     fa->graph_unreg_output_buffers_.size());
}

void get_graph_buffer_ipc_meta(fptr_t _fa,
                               int64_t handle_out,
                               int64_t offset_out)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    auto [handle_bytes, offsets] = fa->get_graph_buffer_ipc_meta();
    std::memcpy((void*)handle_out, handle_bytes.data(), handle_bytes.size());
    std::memcpy((void*)offset_out, offsets.data(), offsets.size() * sizeof(int64_t));
}

void register_graph_buffers(fptr_t _fa,
                            const std::vector<int64_t>& handle_ptrs,
                            const std::vector<int64_t>& offset_ptrs)
{
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    int world_size = handle_ptrs.size();
    std::vector<const void*> handles(world_size);
    std::vector<const int64_t*> offsets(world_size);
    for(int i = 0; i < world_size; i++)
    {
        handles[i] = (const void*)handle_ptrs[i];
        offsets[i] = (const int64_t*)offset_ptrs[i];
    }
    fa->register_graph_buffers(handles.data(), offsets.data());
}

// ---- ROCm-specific utilities ----

#ifdef USE_ROCM

bool fabric_ar_available()
{
#ifdef AITER_ENABLE_SUPERNODE_AR
    return true;
#else
    return false;
#endif
}

int64_t ar_handle_size(int64_t transport)
{
    if(transport == static_cast<int64_t>(ARTransport::IPC))
        return sizeof(hipIpcMemHandle_t);
    if(transport != static_cast<int64_t>(ARTransport::Fabric))
        throw std::invalid_argument("invalid custom allreduce transport");
#ifdef AITER_ENABLE_SUPERNODE_AR
    return sizeof(hsa_ext_rpc_memory_t);
#else
    throw std::runtime_error(
        "fabric custom allreduce was not compiled; rebuild module_custom_all_reduce "
        "with supernode support enabled (the build default)");
#endif
}

int64_t allocate_meta_buffer(int64_t size, int64_t transport)
{
    int device_index;
    HIP_CALL(hipGetDevice(&device_index));
    HipDeviceGuard device_guard(device_index);
    hipStream_t stream = aiter::getCurrentHIPStream();
    void* buffer = nullptr;
    hipStreamCaptureMode mode = hipStreamCaptureModeRelaxed;
    HIP_CALL(hipThreadExchangeStreamCaptureMode(&mode));
    // Try uncached allocation first. Fabric memory must remain exportable, so
    // its fallback is fine-grained memory rather than a regular hipMalloc.
    hipError_t err = hipExtMallocWithFlags((void**)&buffer, size, hipDeviceMallocUncached);
    if(err != hipSuccess)
    {
        if(transport == static_cast<int64_t>(ARTransport::Fabric))
        {
#ifdef AITER_ENABLE_SUPERNODE_AR
            err = hipExtMallocWithFlags((void**)&buffer, size, hipDeviceMallocFinegrained);
#else
            HIP_CALL(hipThreadExchangeStreamCaptureMode(&mode));
            throw std::runtime_error(
                "fabric custom allreduce was not compiled; rebuild module_custom_all_reduce "
                "with supernode support enabled (the build default)");
#endif
        }
        else if(transport == static_cast<int64_t>(ARTransport::IPC))
        {
            err = hipMalloc((void**)&buffer, size);
        }
        else
        {
            HIP_CALL(hipThreadExchangeStreamCaptureMode(&mode));
            throw std::invalid_argument("invalid custom allreduce transport");
        }
        if(err != hipSuccess)
        {
            HIP_CALL(hipThreadExchangeStreamCaptureMode(&mode));
            throw std::runtime_error(
                std::string("allocate_meta_buffer: exportable allocation(") +
                std::to_string(size) + " bytes) failed: " +
                hipGetErrorString(err));
        }
    }
    HIP_CALL(hipMemsetAsync(buffer, 0, size, stream));
    HIP_CALL(hipStreamSynchronize(stream));
    HIP_CALL(hipThreadExchangeStreamCaptureMode(&mode));
    return (int64_t)buffer;
}

void free_meta_buffer(int64_t ptr)
{
    HIP_CALL(hipFree((void*)ptr));
}

void get_meta_buffer_handle(int64_t inp_ptr,
                            int64_t size,
                            int64_t out_handle_ptr,
                            int64_t transport)
{
    if(transport == static_cast<int64_t>(ARTransport::IPC))
    {
        HIP_CALL(hipIpcGetMemHandle(
            reinterpret_cast<hipIpcMemHandle_t*>(out_handle_ptr),
            reinterpret_cast<void*>(inp_ptr)));
        return;
    }
    if(transport != static_cast<int64_t>(ARTransport::Fabric))
        throw std::invalid_argument("invalid custom allreduce transport");
#ifdef AITER_ENABLE_SUPERNODE_AR
    const hsa_status_t status = hsa_ext_rpc_memory_create(
        reinterpret_cast<void*>(inp_ptr),
        static_cast<size_t>(size),
        reinterpret_cast<hsa_ext_rpc_memory_t*>(out_handle_ptr));
    if(status != HSA_STATUS_SUCCESS)
        throw std::runtime_error("hsa_ext_rpc_memory_create failed with status " +
                                 std::to_string(static_cast<int>(status)));
#else
    throw std::runtime_error(
        "fabric custom allreduce was not compiled; rebuild module_custom_all_reduce "
        "with supernode support enabled (the build default)");
#endif
}

void get_meta_buffer_ipc_handle(int64_t inp_ptr, int64_t out_handle_ptr)
{
    HIP_CALL(hipIpcGetMemHandle((hipIpcMemHandle_t*)out_handle_ptr, (void*)inp_ptr));
}

#endif

// ---- Public collective APIs ----

void all_reduce(fptr_t _fa,
                const aiter_tensor_t& inp,
                const aiter_tensor_t& out,
                bool use_new, bool open_fp8_quant,
                int64_t reg_inp_ptr, int64_t reg_inp_bytes)
{
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int64_t numel  = inp.numel();
    int64_t data_bytes = numel * inp.element_size();

    if(numel <= 0 || data_bytes % 16 != 0)
        throw std::invalid_argument("all_reduce requires a positive multiple of 16 input bytes");
    if(out.numel() != numel || out.dtype() != dtype || out.device_id != inp.device_id)
        throw std::invalid_argument("all_reduce output size, dtype and device must match input");

    void* actual_inp = inp.data_ptr();
    void* actual_out = out.data_ptr();

    // reg_inp_ptr == 0 means the input tensor itself is IPC-registered
    // (graph mode), so the write-mode kernel can directly write to peer
    // GPUs via IPC-registered output buffers.  In eager mode (reg_inp_ptr
    // != 0) the output is not IPC-registered, kernel uses temp-buffer path.
    bool is_broadcast_reg_outptr = (reg_inp_ptr == 0);

    if(reg_inp_ptr != 0)
    {
        if(data_bytes > reg_inp_bytes)
            throw std::runtime_error("registered buffer is too small to contain the input");

        // LL publishes local input into peer-readable scratch itself. Avoid a
        // preceding staging copy only for this protocol; do not register an
        // arbitrary cached allocation for direct peer reads. Preserve the
        // staging behavior for unaligned slices and overlapping input/output.
        const auto in_addr = reinterpret_cast<uintptr_t>(actual_inp);
        const auto out_addr = reinterpret_cast<uintptr_t>(actual_out);
        const auto distance = in_addr < out_addr ? out_addr - in_addr : in_addr - out_addr;
        if((in_addr % 16 == 0) && (out_addr % 16 == 0) &&
           distance >= static_cast<uint64_t>(data_bytes))
        {
            auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
            if(dtype == AITER_DTYPE_fp16 && !(open_fp8_quant && numel >= 128 * 2048))
            {
                if(fa->try_small_allreduce(stream, reinterpret_cast<opus::fp16_t*>(actual_inp),
                                          reinterpret_cast<opus::fp16_t*>(actual_out),
                                          numel, use_new, false))
                    return;
            }
#if (__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
            else if(dtype == AITER_DTYPE_bf16)
            {
                if(fa->try_small_allreduce(stream, reinterpret_cast<opus::bf16_t*>(actual_inp),
                                          reinterpret_cast<opus::bf16_t*>(actual_out),
                                          numel, use_new, false))
                    return;
            }
#endif
        }
        HIP_CALL(hipMemcpyAsync((void*)reg_inp_ptr, actual_inp, data_bytes,
                                hipMemcpyDeviceToDevice, stream));
        actual_inp = (void*)reg_inp_ptr;
    }

    _all_reduce(_fa, actual_inp, actual_out, numel, dtype,
                use_new, open_fp8_quant, is_broadcast_reg_outptr);
}

void reduce_scatter_dim(fptr_t _fa,
                        const aiter_tensor_t& inp, const aiter_tensor_t& out,
                        int64_t m, int64_t n, int64_t k, int64_t split_dim,
                        int64_t reg_ptr, int64_t reg_bytes);

void reduce_scatter(fptr_t _fa,
                    const aiter_tensor_t& inp,
                    const aiter_tensor_t& out,
                    int64_t reg_ptr, int64_t reg_bytes)
{
    if(inp.dtype() == AITER_DTYPE_i8 || inp.dtype() == AITER_DTYPE_fp8)
    {
        reduce_scatter_dim(_fa, inp, out, 0, 0, inp.numel(), 0, reg_ptr, reg_bytes);
        return;
    }
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int64_t inp_numel  = inp.numel();
    int64_t data_bytes = inp_numel * inp.element_size();

    if(reg_ptr != 0)
    {
        if(data_bytes > reg_bytes)
            throw std::runtime_error("registered buffer is too small to contain the input");
        HIP_CALL(hipMemcpyAsync((void*)reg_ptr, inp.data_ptr(), data_bytes,
                                hipMemcpyDeviceToDevice, stream));
        _reduce_scatter(_fa, (void*)reg_ptr, out.data_ptr(), inp_numel, dtype);
    }
    else
    {
        _reduce_scatter(_fa, inp.data_ptr(), out.data_ptr(), inp_numel, dtype);
    }
}


// Shared validation/copy-in for the existing and explicit-format entry points.
static void reduce_scatter_impl(fptr_t _fa,
                        const aiter_tensor_t& inp, const aiter_tensor_t& out,
                        int64_t m, int64_t n, int64_t k, int64_t split_dim,
                        int64_t reg_ptr, int64_t reg_bytes, int format)
{
    if(!_fa || !inp.is_gpu() || !out.is_gpu())
        throw std::invalid_argument("reduce_scatter requires a live handle and GPU tensors");
    HipDeviceGuard device_guard(inp.device_id);
    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    const auto world = fa->world_size_;
    if(world != 2 && world != 4 && world != 8)
        throw std::invalid_argument("reduce_scatter supports world sizes 2, 4, 8");
    if(inp.dtype() != out.dtype() || inp.device_id != out.device_id ||
       !inp.is_contiguous() || !out.is_contiguous())
        throw std::invalid_argument("reduce_scatter requires matching contiguous tensors on one device");
    if(format >= 0 && ((format != 0 && format != 1 && format != 3) || inp.element_size() != 1))
        throw std::invalid_argument("invalid 8-bit reduce_scatter format");
    if(inp.numel() == 0 || inp.numel() > INT32_MAX || out.numel() != inp.numel() / world ||
       inp.numel() % world != 0)
        throw std::invalid_argument("reduce_scatter input/output size mismatch");
    const int pack = 16 / inp.element_size();
    bool valid = false;
    if(split_dim == 0)
        valid = m == 0 && n == 0 && k == static_cast<int64_t>(inp.numel()) && k % (world * pack) == 0;
    else if(split_dim == 1)
        valid = m == 0 && n > 0 && k > 0 && n <= INT32_MAX && k <= INT32_MAX &&
                n * k == static_cast<int64_t>(inp.numel()) && k % world == 0;
    else if(split_dim == 2)
        valid = m > 0 && n > 0 && k > 0 && m <= INT32_MAX && n <= INT32_MAX && k <= INT32_MAX &&
                m <= static_cast<int64_t>(inp.numel()) / n && m * n <= static_cast<int64_t>(inp.numel()) / k &&
                m * n * k == static_cast<int64_t>(inp.numel()) && n % world == 0;
    if(!valid)
        throw std::invalid_argument("invalid reduce_scatter dimensions or alignment");
    const int64_t bytes = inp.numel() * inp.element_size();
    const auto input_begin = reinterpret_cast<uintptr_t>(inp.data_ptr());
    const auto output_begin = reinterpret_cast<uintptr_t>(out.data_ptr());
    if(output_begin % 16 || (!reg_ptr && input_begin % 16) || (reg_ptr && reg_ptr % 16))
        throw std::invalid_argument("reduce_scatter buffers must be 16-byte aligned");
    if(input_begin < output_begin + out.numel() * out.element_size() &&
       output_begin < input_begin + bytes)
        throw std::invalid_argument("reduce_scatter input and output must not overlap");
    auto stream = aiter::getCurrentHIPStream();
    void* input = inp.data_ptr();
    if(reg_ptr)
    {
        if(bytes > reg_bytes)
            throw std::invalid_argument("registered buffer is too small to contain the input");
        HIP_CALL(hipMemcpyAsync(reinterpret_cast<void*>(reg_ptr), input, bytes, hipMemcpyDeviceToDevice, stream));
        input = reinterpret_cast<void*>(reg_ptr);
    }
    if(format >= 0)
    {
#define RS_FORMAT_CASE(FORMAT) \
        case FORMAT: fa->dispatchReduceScatter8Bit<FORMAT>(stream, \
            reinterpret_cast<unsigned char*>(input), reinterpret_cast<unsigned char*>(out.data_ptr()), \
            inp.numel(), n, k, split_dim); break
        switch(format)
        {
            RS_FORMAT_CASE(0);
            RS_FORMAT_CASE(1);
            RS_FORMAT_CASE(3);
        }
#undef RS_FORMAT_CASE
        return;
    }
#define RS_DIM_CASE(TYPE, ENUM) \
    case ENUM: fa->dispatchReduceScatter<TYPE>(stream, reinterpret_cast<TYPE*>(input), \
        reinterpret_cast<TYPE*>(out.data_ptr()), m, n, k, \
        static_cast<ReduceScatterSplitDim>(split_dim)); break
    switch(inp.dtype())
    {
        RS_DIM_CASE(opus::fp32_t, AITER_DTYPE_fp32);
        RS_DIM_CASE(opus::fp16_t, AITER_DTYPE_fp16);
        RS_DIM_CASE(opus::bf16_t, AITER_DTYPE_bf16);
        default: throw std::invalid_argument("reduce_scatter supports float32, float16 and bfloat16");
    }
#undef RS_DIM_CASE
}

void reduce_scatter_dim(fptr_t _fa,
                        const aiter_tensor_t& inp, const aiter_tensor_t& out,
                        int64_t m, int64_t n, int64_t k, int64_t split_dim,
                        int64_t reg_ptr, int64_t reg_bytes)
{
    const int format = inp.dtype() == AITER_DTYPE_i8 ? 0 : (inp.dtype() == AITER_DTYPE_fp8 ? 1 : -1);
    reduce_scatter_impl(_fa, inp, out, m, n, k, split_dim, reg_ptr, reg_bytes, format);
}

void reduce_scatter_8bit(fptr_t _fa,
                         const aiter_tensor_t& inp, const aiter_tensor_t& out,
                         int64_t m, int64_t n, int64_t k, int64_t split_dim,
                         int64_t reg_ptr, int64_t reg_bytes, int64_t format)
{
    if((format != 0 && format != 1 && format != 3) ||
       inp.dtype() != AITER_DTYPE_u8 || out.dtype() != AITER_DTYPE_u8)
        throw std::invalid_argument("8-bit reduce_scatter requires uint8 views and format 0, 1 or 3");
    reduce_scatter_impl(_fa, inp, out, m, n, k, split_dim, reg_ptr, reg_bytes, static_cast<int>(format));
}

void all_gather_reg(fptr_t _fa,
                    const aiter_tensor_t& inp,
                    const aiter_tensor_t& out,
                    int64_t dim)
{
    HipDeviceGuard device_guard(inp.device_id);
    int64_t last_dim_size = inp.size(-1);
    _all_gather(_fa, inp.data_ptr(), out.data_ptr(), inp.numel(), inp.dtype(),
                last_dim_size, dim);
}

void all_gather_unreg(fptr_t _fa,
                      const aiter_tensor_t& inp,
                      int64_t reg_buffer,
                      const aiter_tensor_t& out,
                      int64_t reg_bytes,
                      int64_t dim)
{
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    int64_t data_bytes = inp.numel() * inp.element_size();
    int64_t last_dim_size = inp.size(-1);

    if(data_bytes > reg_bytes)
        throw std::runtime_error("registered buffer is too small to contain the input");
    HIP_CALL(hipMemcpyAsync((void*)reg_buffer, inp.data_ptr(), data_bytes,
                            hipMemcpyDeviceToDevice, stream));
    _all_gather(_fa, (void*)reg_buffer, out.data_ptr(), inp.numel(), inp.dtype(),
                last_dim_size, dim);
}

// Validate tensor metadata before any copy or collective launch. The optional
// mirror remains an opaque pointer in the upstream ABI; Python owns its shape.
static void validate_fused_norm_tensors(
    fptr_t handle, const aiter_tensor_t& inp, const aiter_tensor_t& residual,
    const aiter_tensor_t& residual_out, const aiter_tensor_t& out,
    const aiter_tensor_t& weight, int quant_kind = 0,
    const aiter_tensor_t* scale = nullptr, int64_t group_size = 1,
    bool transpose_scale = false)
{
    if(!handle || !inp.is_gpu() || inp.dim() < 2 || inp.numel() == 0 ||
       inp.numel() > INT32_MAX || weight.dim() != 1 || weight.numel() == 0)
        throw std::invalid_argument("fused norm requires a handle and nonempty GPU input/weight");
    const auto world = reinterpret_cast<aiter::CustomAllreduce*>(handle)->world_size_;
    if(world != 2 && world != 4 && world != 8)
        throw std::invalid_argument("fused norm supports world sizes 2, 4, 8");
    const auto dtype = inp.dtype();
    if(dtype != AITER_DTYPE_fp16 && dtype != AITER_DTYPE_bf16 && dtype != AITER_DTYPE_fp32)
        throw std::invalid_argument("unsupported fused norm input dtype");
    if(quant_kind >= 2 && dtype == AITER_DTYPE_fp32)
        throw std::invalid_argument("group and MXFP4 fusion require float16 or bfloat16");
    const int64_t width = weight.numel(), input_width = inp.size(-1);
    const int64_t pack = 16 / inp.element_size();
    if(input_width < width || width % pack || input_width % pack ||
       (!inp.is_contiguous() && !_can_pack_2d_last_dim_slice(inp, inp.size(0), input_width)))
        throw std::invalid_argument("invalid fused norm input layout or packed width");
    auto matches = [&](const aiter_tensor_t& t, int64_t last, AiterDtype dt, bool contiguous) {
        if(t.device_id != inp.device_id || t.dtype() != dt || t.dim() != inp.dim() ||
           t.size(-1) != last || (contiguous && !t.is_contiguous())) return false;
        for(int d = 0; d < inp.dim() - 1; ++d)
            if(t.size(d) != inp.size(d)) return false;
        return true;
    };
    if(weight.device_id != inp.device_id || weight.dtype() != dtype || !weight.is_contiguous() ||
       !matches(residual, width, dtype, true) || !matches(residual_out, width, dtype, true))
        throw std::invalid_argument("fused norm residual/weight shape, dtype, device or layout mismatch");
    if(quant_kind == 0)
    {
        if(out.dim() < 1 || out.size(-1) < width || out.size(-1) % pack ||
           !matches(out, out.size(-1), dtype, true))
            throw std::invalid_argument("invalid fused norm output");
        return;
    }
    if(input_width != width || width / pack > 1024 || group_size <= 0 || width % group_size)
        throw std::invalid_argument("invalid quantized fusion width or group size");
    const bool fp4 = quant_kind == 3;
    if(fp4 && !inp.is_contiguous())
        throw std::invalid_argument("MXFP4 fusion requires contiguous input");
    const auto out_dtype = out.dtype();
    if((fp4 && out_dtype != AITER_DTYPE_u8) ||
       (!fp4 && out_dtype != AITER_DTYPE_fp8 && out_dtype != AITER_DTYPE_u8) ||
       !matches(out, fp4 ? width / 2 : width, out_dtype, true))
        throw std::invalid_argument("invalid quantized output metadata");
    const auto groups = quant_kind == 1 ? 1 : width / group_size;
    if(!scale || !matches(*scale, groups, fp4 ? AITER_DTYPE_u8 : AITER_DTYPE_fp32, !transpose_scale))
        throw std::invalid_argument("invalid quantized scale metadata");
    if(transpose_scale && (inp.dim() != 2 || scale->stride(0) != 1 || scale->stride(1) != inp.size(0)))
        throw std::invalid_argument("transpose scale requires shape (M, groups), strides (1, M)");
}

void fused_allreduce_rmsnorm(fptr_t _fa,
                             const aiter_tensor_t& inp,
                             const aiter_tensor_t& res_inp,
                             const aiter_tensor_t& res_out,
                             const aiter_tensor_t& out,
                             const aiter_tensor_t& w,
                             double eps,
                             int64_t reg_ptr, int64_t reg_bytes,
                             bool use_1stage,
                             bool gemma_norm)
{
    validate_fused_norm_tensors(_fa, inp, res_inp, res_out, out, w);
    if(!reg_ptr && !inp.is_contiguous())
        throw std::invalid_argument("strided fused input requires a registered copy-in buffer");
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int input_n = (int)inp.size(-1);
    int n = (int)w.numel();
    int m = (int)(inp.numel() / input_n);
    int out_n = (int)out.size(-1);
    if(input_n != n || out_n != n)
    {
        throw std::runtime_error(
            "fused allreduce rmsnorm requires input/output width == weight width; "
            "use fused_allreduce_rmsnorm_pad for padded storage or padded outputs");
    }
    if((int)res_inp.size(-1) != n || (int)res_out.size(-1) != n)
    {
        throw std::runtime_error(
            "fused allreduce rmsnorm requires residual input/output width == weight width");
    }

    if(reg_ptr != 0)
    {
        _copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);
        _fused_allreduce_rmsnorm(_fa,
                                 (void*)reg_ptr, res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), nullptr, w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, out_n, use_1stage, gemma_norm);
    }
    else
    {
        _fused_allreduce_rmsnorm(_fa,
                                 inp.data_ptr(), res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), nullptr, w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, out_n, use_1stage, gemma_norm);
    }
}

void fused_allreduce_rmsnorm_pad(fptr_t _fa,
                                 const aiter_tensor_t& inp,
                                 const aiter_tensor_t& res_inp,
                                 const aiter_tensor_t& res_out,
                                 const aiter_tensor_t& out,
                                 const aiter_tensor_t& w,
                                 double eps,
                                 int64_t reg_ptr, int64_t reg_bytes,
                                 bool use_1stage,
                                 bool gemma_norm)
{
    validate_fused_norm_tensors(_fa, inp, res_inp, res_out, out, w);
    if(!reg_ptr && !inp.is_contiguous())
        throw std::invalid_argument("strided fused input requires a registered copy-in buffer");
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int input_n = (int)inp.size(-1);
    int n = (int)w.numel();
    int m = (int)(inp.numel() / input_n);
    int out_n = (int)out.size(-1);
    if(input_n < n)
    {
        throw std::runtime_error(
            "fused allreduce rmsnorm pad requires input width >= weight width");
    }
    if((int)res_inp.size(-1) != n || (int)res_out.size(-1) != n)
    {
        throw std::runtime_error(
            "fused allreduce rmsnorm pad requires residual input/output width == weight width");
    }

    if(reg_ptr != 0)
    {
        _copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);
        _fused_allreduce_rmsnorm(_fa,
                                 (void*)reg_ptr, res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), nullptr, w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, out_n, use_1stage, gemma_norm);
    }
    else
    {
        _fused_allreduce_rmsnorm(_fa,
                                 inp.data_ptr(), res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), nullptr, w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, out_n, use_1stage, gemma_norm);
    }
}

void fused_allreduce_rmsnorm_quant(fptr_t _fa,
                                   const aiter_tensor_t& inp,
                                   const aiter_tensor_t& res_inp,
                                   const aiter_tensor_t& res_out,
                                   const aiter_tensor_t& out,
                                   const aiter_tensor_t& scale_out,
                                   const aiter_tensor_t& w,
                                   double eps,
                                   int64_t reg_ptr, int64_t reg_bytes,
                                   bool use_1stage,
                                   bool gemma_norm,
                                   int64_t bf16_out_ptr)
{
    validate_fused_norm_tensors(_fa, inp, res_inp, res_out, out, w, 1, &scale_out);
    if(!reg_ptr && !inp.is_contiguous())
        throw std::invalid_argument("strided fused input requires a registered copy-in buffer");
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int input_n = (int)inp.size(-1);
    int n = (int)w.numel();
    int m = (int)(inp.numel() / input_n);
    if(input_n != n)
    {
        throw std::runtime_error(
            "fused allreduce rmsnorm quant requires input width == weight width");
    }

    // bf16_out_ptr is an opaque data pointer (0 = not requested). When non-zero
    // the kernel also writes the pre-quantization bf16/fp16 normed output, used
    // by v32 DSA models (e.g. GLM-5.2) whose indexer GEMMs consume bf16.
    void* bf16_out = reinterpret_cast<void*>(bf16_out_ptr);

    if(reg_ptr != 0)
    {
        _copy_input_to_registered_buffer(inp, m, input_n, stream, reg_ptr, reg_bytes);
        _fused_allreduce_rmsnorm(_fa,
                                 (void*)reg_ptr, res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), scale_out.data_ptr(), w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, n, use_1stage, gemma_norm,
                                 bf16_out);
    }
    else
    {
        _fused_allreduce_rmsnorm(_fa,
                                 inp.data_ptr(), res_inp.data_ptr(), res_out.data_ptr(),
                                 out.data_ptr(), scale_out.data_ptr(), w.data_ptr(),
                                 dtype, (float)eps, m, input_n, n, n, use_1stage, gemma_norm,
                                 bf16_out);
    }
}

void fused_allreduce_rmsnorm_quant_per_group(fptr_t _fa,
                                             const aiter_tensor_t& inp,
                                             const aiter_tensor_t& res_inp,
                                             const aiter_tensor_t& res_out,
                                             const aiter_tensor_t& out,
                                             const aiter_tensor_t& scale_out,
                                             const aiter_tensor_t& w,
                                             double eps,
                                             int64_t group_size,
                                             int64_t reg_ptr, int64_t reg_bytes,
                                             bool use_1stage,
                                             int64_t bf16_out_ptr,
                                             bool transpose_scale)
{
    validate_fused_norm_tensors(_fa, inp, res_inp, res_out, out, w, 2, &scale_out, group_size, transpose_scale);
    if(!reg_ptr && !inp.is_contiguous())
        throw std::invalid_argument("strided fused input requires a registered copy-in buffer");
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype     = inp.dtype();
    int64_t numel  = inp.numel();
    int64_t data_bytes = numel * inp.element_size();
    int n = (int)w.numel();
    int m = (int)(numel / w.numel());

    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);

    void* inp_ptr = inp.data_ptr();
    if(reg_ptr != 0)
    {
        _copy_input_to_registered_buffer(inp, m, n, stream, reg_ptr, reg_bytes);
        inp_ptr = (void*)reg_ptr;
    }

    // bf16_out_ptr is an opaque data pointer (0 = not requested). When non-zero
    // the fused kernel writes the pre-quantization bf16/fp16 normed output so
    // GDN-style callers can keep an unquantized view without launching a
    // separate per-group quant kernel.
    void* bf16_out = reinterpret_cast<void*>(bf16_out_ptr);

    switch(dtype)
    {
#if(__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        fa->dispatchFusedAllReduceRMSNormQuantPerGroup<opus::bf16_t, fp8_type>(
            stream,
            reinterpret_cast<opus::bf16_t*>(inp_ptr),
            reinterpret_cast<opus::bf16_t*>(res_inp.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(res_out.data_ptr()),
            reinterpret_cast<fp8_type*>(out.data_ptr()),
            reinterpret_cast<float*>(scale_out.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(w.data_ptr()),
            (float)eps, m, n, (int)group_size, use_1stage,
            reinterpret_cast<opus::bf16_t*>(bf16_out), transpose_scale);
        break;
    }
#endif
    case AITER_DTYPE_fp16: {
        fa->dispatchFusedAllReduceRMSNormQuantPerGroup<opus::fp16_t, fp8_type>(
            stream,
            reinterpret_cast<opus::fp16_t*>(inp_ptr),
            reinterpret_cast<opus::fp16_t*>(res_inp.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(res_out.data_ptr()),
            reinterpret_cast<fp8_type*>(out.data_ptr()),
            reinterpret_cast<float*>(scale_out.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(w.data_ptr()),
            (float)eps, m, n, (int)group_size, use_1stage,
            reinterpret_cast<opus::fp16_t*>(bf16_out), transpose_scale);
        break;
    }
    default:
        throw std::runtime_error(
            "fused_allreduce_rmsnorm_quant_per_group only supports float16 and bfloat16");
    }
}

void fused_allreduce_rmsnorm_mxfp4_quant(fptr_t _fa,
                                         const aiter_tensor_t& inp,
                                         const aiter_tensor_t& res_inp,
                                         const aiter_tensor_t& res_out,
                                         const aiter_tensor_t& out,
                                         const aiter_tensor_t& scale_out,
                                         const aiter_tensor_t& w,
                                         double eps,
                                         int64_t reg_ptr, int64_t reg_bytes,
                                         bool use_1stage,
                                         int64_t bf16_out_ptr)
{
    validate_fused_norm_tensors(_fa, inp, res_inp, res_out, out, w, 3, &scale_out, 32);
    HipDeviceGuard device_guard(inp.device_id);
    hipStream_t stream = aiter::getCurrentHIPStream();
    auto dtype         = inp.dtype();
    int64_t numel      = inp.numel();
    int64_t data_bytes = numel * inp.element_size();
    int n              = (int)w.numel();
    int m              = (int)(numel / w.numel());

    auto fa = reinterpret_cast<aiter::CustomAllreduce*>(_fa);

    void* inp_ptr = inp.data_ptr();
    if(reg_ptr != 0)
    {
        if(data_bytes > reg_bytes)
            throw std::runtime_error("registered buffer is too small to contain the input");
        HIP_CALL(hipMemcpyAsync((void*)reg_ptr, inp.data_ptr(), data_bytes,
                                hipMemcpyDeviceToDevice, stream));
        inp_ptr = (void*)reg_ptr;
    }

    void* bf16_out = reinterpret_cast<void*>(bf16_out_ptr);

    switch(dtype)
    {
#if(__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        fa->dispatchFusedAllReduceRMSNormQuantMXFP4<opus::bf16_t>(
            stream,
            reinterpret_cast<opus::bf16_t*>(inp_ptr),
            reinterpret_cast<opus::bf16_t*>(res_inp.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(res_out.data_ptr()),
            reinterpret_cast<uint8_t*>(out.data_ptr()),
            reinterpret_cast<uint8_t*>(scale_out.data_ptr()),
            reinterpret_cast<opus::bf16_t*>(w.data_ptr()),
            (float)eps, m, n, use_1stage,
            reinterpret_cast<opus::bf16_t*>(bf16_out));
        break;
    }
#endif
    case AITER_DTYPE_fp16: {
        fa->dispatchFusedAllReduceRMSNormQuantMXFP4<opus::fp16_t>(
            stream,
            reinterpret_cast<opus::fp16_t*>(inp_ptr),
            reinterpret_cast<opus::fp16_t*>(res_inp.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(res_out.data_ptr()),
            reinterpret_cast<uint8_t*>(out.data_ptr()),
            reinterpret_cast<uint8_t*>(scale_out.data_ptr()),
            reinterpret_cast<opus::fp16_t*>(w.data_ptr()),
            (float)eps, m, n, use_1stage,
            reinterpret_cast<opus::fp16_t*>(bf16_out));
        break;
    }
    default:
        throw std::runtime_error(
            "fused_allreduce_rmsnorm_mxfp4_quant only supports float16 and bfloat16");
    }
}

void fused_qknorm_allreduce(fptr_t _fa,
                            const aiter_tensor_t& qkv_in,
                            const aiter_tensor_t& q_w,
                            const aiter_tensor_t& k_w,
                            const aiter_tensor_t& q_out,
                            const aiter_tensor_t& k_out,
                            const aiter_tensor_t& v_out,
                            double eps,
                            int64_t reg_ptr,
                            int64_t reg_bytes)
{
    HipDeviceGuard device_guard(qkv_in.device_id);
    hipStream_t stream   = aiter::getCurrentHIPStream();
    auto dtype           = qkv_in.dtype();
    int64_t hidden_dim_q = q_w.numel();
    int64_t hidden_dim_k = k_w.numel();
    int64_t token_num    = qkv_in.size(0);
    int64_t hidden_dim_v = qkv_in.size(1) - (hidden_dim_q + hidden_dim_k);
    auto fa              = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    int64_t data_bytes   = qkv_in.numel() * qkv_in.element_size();
    void* inp_ptr        = qkv_in.data_ptr();

    if(reg_ptr != 0)
    {
        if(data_bytes > reg_bytes)
            throw std::runtime_error("registered buffer is too small to contain the input");
        HIP_CALL(hipMemcpyAsync((void*)reg_ptr, qkv_in.data_ptr(), data_bytes,
                                hipMemcpyDeviceToDevice, stream));
        inp_ptr = (void*)reg_ptr;
    }

#define DISPATCH_AR_FUSION(DTYPE)                                                           \
    {                                                                                       \
        fa->dispatchFusedQKNormAllReduce<DTYPE>(stream,                                     \
                                                reinterpret_cast<DTYPE*>(inp_ptr),          \
                                                reinterpret_cast<DTYPE*>(q_w.data_ptr()),   \
                                                reinterpret_cast<DTYPE*>(k_w.data_ptr()),   \
                                                reinterpret_cast<DTYPE*>(q_out.data_ptr()), \
                                                reinterpret_cast<DTYPE*>(k_out.data_ptr()), \
                                                reinterpret_cast<DTYPE*>(v_out.data_ptr()), \
                                                token_num,                                  \
                                                hidden_dim_q,                               \
                                                hidden_dim_k,                               \
                                                hidden_dim_v,                               \
                                                eps);                                       \
    }

    switch(dtype)
    {
    case AITER_DTYPE_fp32: {
        DISPATCH_AR_FUSION(opus::fp32_t)
        break;
    }
    case AITER_DTYPE_fp16: {
        DISPATCH_AR_FUSION(opus::fp16_t)
        break;
    }
#if(__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        DISPATCH_AR_FUSION(opus::bf16_t)
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allreduce only supports float32, float16 and bfloat16");
    }
}

void fused_qknorm_allreduce_rope(fptr_t _fa,
                                 const aiter_tensor_t& qkv_in,
                                 const aiter_tensor_t& q_w,
                                 const aiter_tensor_t& k_w,
                                 const aiter_tensor_t& q_out,
                                 const aiter_tensor_t& k_out,
                                 const aiter_tensor_t& v_out,
                                 const aiter_tensor_t& cos_sin_cache,
                                 const aiter_tensor_t& position_ids,
                                 int64_t head_dim,
                                 int64_t rotary_dim,
                                 double eps,
                                 int64_t reg_ptr,
                                 int64_t reg_bytes)
{
    if(!_fa || qkv_in.dim() != 2 || cos_sin_cache.dim() != 2 ||
       qkv_in.numel() == 0 || !qkv_in.is_gpu())
        throw std::invalid_argument("invalid QK RoPE input or communicator");
    for(const auto* t : {&q_w, &k_w, &q_out, &k_out, &v_out, &cos_sin_cache})
        if(!t->is_contiguous() || t->device_id != qkv_in.device_id || t->dtype() != qkv_in.dtype())
            throw std::invalid_argument("QK RoPE tensors must be contiguous with matching dtype/device");
    if(!qkv_in.is_contiguous() || !position_ids.is_contiguous() ||
       position_ids.device_id != qkv_in.device_id || position_ids.numel() != size_t(qkv_in.size(0)) ||
       q_w.dim() != 1 || k_w.dim() != 1 || q_w.numel() == 0 || k_w.numel() == 0 ||
       qkv_in.size(1) <= int64_t(q_w.numel() + k_w.numel()) || cos_sin_cache.size(0) <= 0)
        throw std::invalid_argument("invalid QK RoPE layout, weights or positions");
    if(q_out.numel() != size_t(qkv_in.size(0)) * q_w.numel() ||
       k_out.numel() != size_t(qkv_in.size(0)) * k_w.numel() ||
       v_out.numel() != qkv_in.numel() - q_out.numel() - k_out.numel())
        throw std::invalid_argument("QK RoPE output size mismatch");
    HipDeviceGuard device_guard(qkv_in.device_id);
    hipStream_t stream   = aiter::getCurrentHIPStream();
    auto dtype           = qkv_in.dtype();
    int64_t hidden_dim_q = q_w.numel();
    int64_t hidden_dim_k = k_w.numel();
    int64_t token_num    = qkv_in.size(0);
    int64_t hidden_dim_v = qkv_in.size(1) - (hidden_dim_q + hidden_dim_k);
    auto fa              = reinterpret_cast<aiter::CustomAllreduce*>(_fa);
    int64_t data_bytes   = qkv_in.numel() * qkv_in.element_size();
    void* inp_ptr        = qkv_in.data_ptr();

    if(qkv_in.dtype() != cos_sin_cache.dtype())
        throw std::runtime_error("fused_qknorm_allreduce_rope requires cos_sin_cache dtype to match qkv_in dtype");
    if(position_ids.dtype() != AITER_DTYPE_i64)
        throw std::runtime_error("fused_qknorm_allreduce_rope requires int64 position_ids");
    if(cos_sin_cache.dim() != 2 || cos_sin_cache.size(1) != rotary_dim)
        throw std::runtime_error("fused_qknorm_allreduce_rope expects cos_sin_cache shape [max_pos, rotary_dim]");

    if(reg_ptr != 0)
    {
        if(data_bytes > reg_bytes)
            throw std::runtime_error("registered buffer is too small to contain the input");
        HIP_CALL(hipMemcpyAsync((void*)reg_ptr, qkv_in.data_ptr(), data_bytes,
                                hipMemcpyDeviceToDevice, stream));
        inp_ptr = (void*)reg_ptr;
    }

#define DISPATCH_AR_ROPE_FUSION(DTYPE)                                                               \
    {                                                                                                \
        fa->dispatchFusedQKNormAllReduce<DTYPE, true>(stream,                                        \
                                                reinterpret_cast<DTYPE*>(inp_ptr),                   \
                                                reinterpret_cast<DTYPE*>(q_w.data_ptr()),            \
                                                reinterpret_cast<DTYPE*>(k_w.data_ptr()),            \
                                                reinterpret_cast<DTYPE*>(q_out.data_ptr()),          \
                                                reinterpret_cast<DTYPE*>(k_out.data_ptr()),          \
                                                reinterpret_cast<DTYPE*>(v_out.data_ptr()),          \
                                                token_num,                                           \
                                                hidden_dim_q,                                        \
                                                hidden_dim_k,                                        \
                                                hidden_dim_v,                                        \
                                                eps,                                                 \
                                                reinterpret_cast<DTYPE*>(cos_sin_cache.data_ptr()),  \
                                                reinterpret_cast<int64_t*>(position_ids.data_ptr()), \
                                                head_dim,                                            \
                                                rotary_dim, cos_sin_cache.size(0));                                         \
    }

    switch(dtype)
    {
    case AITER_DTYPE_fp32: {
        DISPATCH_AR_ROPE_FUSION(opus::fp32_t)
        break;
    }
    case AITER_DTYPE_fp16: {
        DISPATCH_AR_ROPE_FUSION(opus::fp16_t)
        break;
    }
#if(__CUDA_ARCH__ >= 800 || !defined(__CUDA_ARCH__))
    case AITER_DTYPE_bf16: {
        DISPATCH_AR_ROPE_FUSION(opus::bf16_t)
        break;
    }
#endif
    default:
        throw std::runtime_error("custom allreduce rope only supports float32, float16 and bfloat16");
    }
#undef DISPATCH_AR_ROPE_FUSION
}

} // namespace aiter
