// SPDX-License-Identifier: MIT
// Copyright (c) 2024, Advanced Micro Devices, Inc. All rights reserved.
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
 
#include "rocm_ops.hpp"
#include "custom_all_reduce.h"

namespace {

// Keep the communication extension independent of the PyTorch C++ ABI. Only
// immutable dtype/type objects are retained; tensor pointers, shapes and strides
// are read on every call. The binding holds the GIL and its tensor arguments until
// launch returns, just like the existing Python descriptor conversion.
struct TensorArgument
{
    py::object tensor_type;
    py::dict dtypes;

    TensorArgument()
    {
        auto torch = py::module_::import("torch");
        tensor_type = torch.attr("Tensor");
        const std::pair<const char*, AiterDtype> types[] = {
            {"uint8", AITER_DTYPE_u8}, {"int8", AITER_DTYPE_i8},
            {"int16", AITER_DTYPE_i16}, {"int32", AITER_DTYPE_i32},
            {"int64", AITER_DTYPE_i64}, {"uint32", AITER_DTYPE_u32},
            {"uint64", AITER_DTYPE_u64}, {"float16", AITER_DTYPE_fp16},
            {"bfloat16", AITER_DTYPE_bf16}, {"float32", AITER_DTYPE_fp32},
            {"float8_e4m3fn", AITER_DTYPE_fp8},
        };
        for(const auto& type : types)
            if(py::hasattr(torch, type.first))
                dtypes[torch.attr(type.first)] = static_cast<int>(type.second);
    }

    aiter_tensor_t operator()(py::handle tensor) const
    {
        if(!py::isinstance(tensor, tensor_type))
            throw py::type_error("communication arguments must be torch.Tensor");
        py::tuple shape = tensor.attr("shape");
        if(shape.size() > 8)
            throw py::value_error("aiter_tensor_t supports at most 8 dimensions");
        auto dtype = tensor.attr("dtype");
        if(!dtypes.contains(dtype))
            throw py::value_error("unsupported communication tensor dtype");
        py::tuple strides = tensor.attr("stride")();
        aiter_tensor_t result{};
        result.ndim = static_cast<int>(shape.size());
        result.numel_ = tensor.attr("numel")().cast<size_t>();
        result.ptr = reinterpret_cast<void*>(tensor.attr("data_ptr")().cast<uintptr_t>());
        result.dtype_ = static_cast<AiterDtype>(dtypes[dtype].cast<int>());
        result.device_id = tensor.attr("is_cuda").cast<bool>()
            ? tensor.attr("device").attr("index").cast<int>() : -1;
        for(int i = 0; i < result.ndim; ++i)
        {
            result.shape[i] = shape[i].cast<int64_t>();
            result.strides[i] = strides[i].cast<int64_t>();
        }
        return result;
    }
};

void bind_tensor_collectives(py::module_& m)
{
    const TensorArgument tensor;
    m.def("all_gather_unreg_tensor",
          [tensor](fptr_t fa, py::object inp, int64_t reg_buffer, py::object out,
                   int64_t reg_bytes, int64_t dim, int64_t stream_ptr) {
              auto input = tensor(inp), output = tensor(out);
              aiter::setCurrentHIPStream(reinterpret_cast<hipStream_t>(stream_ptr));
              aiter::all_gather_unreg(fa, input, reg_buffer, output, reg_bytes, dim);
          }, py::arg("_fa"), py::arg("inp"), py::arg("reg_buffer"), py::arg("out"),
          py::arg("reg_bytes"), py::arg("dim"), py::arg("stream_ptr"));
    m.def("all_gather_reg_tensor",
          [tensor](fptr_t fa, py::object inp, py::object out, int64_t dim,
                   int64_t stream_ptr) {
              auto input = tensor(inp), output = tensor(out);
              aiter::setCurrentHIPStream(reinterpret_cast<hipStream_t>(stream_ptr));
              aiter::all_gather_reg(fa, input, output, dim);
          }, py::arg("_fa"), py::arg("inp"), py::arg("out"), py::arg("dim"),
          py::arg("stream_ptr"));
    m.def("reduce_scatter_dim_tensor",
          [tensor](fptr_t fa, py::object inp, py::object out,
                   int64_t m, int64_t n, int64_t k, int64_t split_dim,
                   int64_t reg_ptr, int64_t reg_bytes, int64_t stream_ptr) {
              auto input = tensor(inp), output = tensor(out);
              aiter::setCurrentHIPStream(reinterpret_cast<hipStream_t>(stream_ptr));
              aiter::reduce_scatter_dim(fa, input, output, m, n, k, split_dim,
                                        reg_ptr, reg_bytes);
          }, py::arg("_fa"), py::arg("inp"), py::arg("out"), py::arg("m"),
          py::arg("n"), py::arg("k"), py::arg("split_dim"), py::arg("reg_ptr"),
          py::arg("reg_bytes"), py::arg("stream_ptr"));
    m.def("reduce_scatter_8bit_tensor",
          [tensor](fptr_t fa, py::object inp, py::object out,
                   int64_t m, int64_t n, int64_t k, int64_t split_dim,
                   int64_t reg_ptr, int64_t reg_bytes, int64_t format,
                   int64_t stream_ptr) {
              auto input = tensor(inp), output = tensor(out);
              aiter::setCurrentHIPStream(reinterpret_cast<hipStream_t>(stream_ptr));
              aiter::reduce_scatter_8bit(fa, input, output, m, n, k, split_dim,
                                         reg_ptr, reg_bytes, format);
          }, py::arg("_fa"), py::arg("inp"), py::arg("out"), py::arg("m"),
          py::arg("n"), py::arg("k"), py::arg("split_dim"), py::arg("reg_ptr"),
          py::arg("reg_bytes"), py::arg("format"), py::arg("stream_ptr"));
}

} // namespace

PYBIND11_MODULE(TORCH_EXTENSION_NAME, m)
{
      CUSTOM_ALL_REDUCE_PYBIND;
      bind_tensor_collectives(m);
}
