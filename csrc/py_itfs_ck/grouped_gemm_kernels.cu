// SPDX-License-Identifier: MIT

#include <torch/all.h>
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>

#include <cstdint>
#include <limits>
#include <string>
#include <vector>

#include "ck_grouped_gemm_abi.h"
#include "grouped_gemm_ck.h"

namespace {

// Layout encoding for grouped GEMM, matching the CK C ABI a_layout/b_layout
// convention. Inputs are always contiguous, row-major 2D tensors:
//   NT (default): a=[M,K], b=[N,K]  -> C = A @ B^T   (a_layout='R', b_layout='C')
//   NN          : a=[M,K], b=[K,N]  -> C = A @ B      (a_layout='R', b_layout='R')
//   TN          : a=[K,M], b=[K,N]  -> C = A^T @ B    (a_layout='C', b_layout='R')
// C is always row-major [M, N].
struct grouped_gemm_layout
{
    char a_layout; // 'R' row-major, 'C' column-major (as seen by CK)
    char b_layout;
};

grouped_gemm_layout parse_grouped_gemm_layout(const std::string& layout)
{
    if(layout == "NT")
    {
        return {'R', 'C'};
    }
    if(layout == "NN")
    {
        return {'R', 'R'};
    }
    if(layout == "TN")
    {
        return {'C', 'R'};
    }
    TORCH_CHECK(false, "ck_grouped_gemm: unsupported layout '", layout,
                "', expected one of NT/NN/TN");
    return {'R', 'C'}; // unreachable; silences non-void return warning
}

int dtype_to_grouped_gemm_dtype(const at::ScalarType dtype)
{
    switch(dtype)
    {
    case at::ScalarType::Half: return CK_TILE_HCU_GROUPED_GEMM_FP16;
    case at::ScalarType::BFloat16: return CK_TILE_HCU_GROUPED_GEMM_BF16;
    case at::ScalarType::Float8_e4m3fn: return CK_TILE_HCU_GROUPED_GEMM_FP8;
    case at::ScalarType::Char: return CK_TILE_HCU_GROUPED_GEMM_INT8;
    default: TORCH_CHECK(false, "ck_grouped_gemm: unsupported dtype: ", dtype);
    }
}

at::ScalarType output_dtype(const at::ScalarType dtype)
{
    if(dtype == at::ScalarType::Char)
    {
        return at::ScalarType::Int;
    }
    if(dtype == at::ScalarType::Float8_e4m3fn)
    {
        return at::ScalarType::Float;
    }
    return dtype;
}

void check_grouped_gemm_tensor(const torch::Tensor& t, const char* name)
{
    TORCH_CHECK(t.is_cuda(), "ck_grouped_gemm: ", name, " must be a CUDA tensor");
    TORCH_CHECK(t.dim() == 2, "ck_grouped_gemm: ", name, " tensors must be 2D");
    TORCH_CHECK(t.is_contiguous(), "ck_grouped_gemm: ", name, " tensors must be contiguous");
}

void check_supported_shape(const at::ScalarType dtype, int64_t m, int64_t n, int64_t k)
{
    if(dtype == at::ScalarType::Half || dtype == at::ScalarType::BFloat16)
    {
        TORCH_CHECK(n % 128 == 0 && k % 64 == 0 && k >= 128,
                    "ck_grouped_gemm: fp16/bf16 requires N % 128 == 0, K % 64 == 0, K >= 128");
    }
    else if(dtype == at::ScalarType::Float8_e4m3fn)
    {
        TORCH_CHECK(n % 128 == 0 && k % 128 == 0,
                    "ck_grouped_gemm: fp8 requires N % 128 == 0, K % 128 == 0");
    }
    else if(dtype == at::ScalarType::Char)
    {
        TORCH_CHECK(m % 32 == 0 && n % 32 == 0 && k % 128 == 0,
                    "ck_grouped_gemm: int8 requires M % 32 == 0, N % 32 == 0, K % 128 == 0");
    }
}

torch::Tensor grouped_gemm_workspace(const at::Device& device, int64_t nbytes)
{
    return torch::empty({nbytes}, torch::TensorOptions().dtype(torch::kUInt8).device(device));
}

} // namespace

namespace aiter {
namespace native {

std::vector<torch::Tensor>
ck_grouped_gemm_impl(std::vector<torch::Tensor>& a_tensors,
                     std::vector<torch::Tensor>& b_tensors,
                     std::vector<torch::Tensor>* c_tensors_out,
                     const std::string& layout)
{
    TORCH_CHECK(!a_tensors.empty(), "ck_grouped_gemm: a tensor list must not be empty");
    TORCH_CHECK(a_tensors.size() == b_tensors.size(),
                "ck_grouped_gemm: a and b tensor lists must have the same length");
    if(c_tensors_out != nullptr)
    {
        TORCH_CHECK(c_tensors_out->size() == a_tensors.size(),
                    "ck_grouped_gemm: c tensor list must match a/b length");
    }
    TORCH_CHECK(a_tensors.size() <= static_cast<std::size_t>(std::numeric_limits<int>::max()),
                "ck_grouped_gemm: group count exceeds int range expected by CK C ABI");

    const auto dtype   = a_tensors[0].scalar_type();
    const auto device  = a_tensors[0].device();
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(a_tensors[0]));
    const auto c_dtype = output_dtype(dtype);

    const grouped_gemm_layout gemm_layout = parse_grouped_gemm_layout(layout);
    // NN/TN currently validated only for fp16/bf16 (CK fast configs declare
    // SupportsFastRowMajorB / SupportsFastColumnMajorA for those dtypes).
    if(layout != "NT")
    {
        TORCH_CHECK(dtype == at::ScalarType::Half || dtype == at::ScalarType::BFloat16,
                    "ck_grouped_gemm: layout ", layout,
                    " is only supported for fp16/bf16");
    }

    std::vector<torch::Tensor> outputs;
    outputs.reserve(a_tensors.size());
    std::vector<ck_tile_hcu_grouped_gemm_desc> descs;
    descs.reserve(a_tensors.size());

    for(std::size_t i = 0; i < a_tensors.size(); ++i)
    {
        auto& a = a_tensors[i];
        auto& b = b_tensors[i];
        check_grouped_gemm_tensor(a, "a");
        check_grouped_gemm_tensor(b, "b");
        TORCH_CHECK(a.device() == device && b.device() == device,
                    "ck_grouped_gemm: all tensors must be on the same device");
        TORCH_CHECK(a.scalar_type() == dtype && b.scalar_type() == dtype,
                    "ck_grouped_gemm: all a/b tensors must have the same dtype");

        // Derive logical GEMM dims (m,n,k) and CK strides from the layout.
        // Physical tensors are contiguous row-major; CK interprets stride/layout.
        //   NT: a=[M,K] row  -> a_layout='R', stride_A=K
        //       b=[N,K] row  -> b_layout='C', stride_B=K (read as [K,N] col-major)
        //   NN: a=[M,K] row  -> a_layout='R', stride_A=K
        //       b=[K,N] row  -> b_layout='R', stride_B=N
        //   TN: a=[K,M] row  -> a_layout='C', stride_A=M (read as [M,K] col-major)
        //       b=[K,N] row  -> b_layout='R', stride_B=N
        // C is always [M,N] row-major with stride_C=N.
        int64_t m, n, k;
        int64_t stride_a, stride_b, stride_c;
        if(gemm_layout.a_layout == 'R')
        {
            m = a.size(0);
            k = a.size(1);
            stride_a = a.size(1); // K
        }
        else // 'C': a stored [K,M] row-major, logical A is [M,K]
        {
            k = a.size(0);
            m = a.size(1);
            stride_a = a.size(1); // M
        }
        if(gemm_layout.b_layout == 'C')
        {
            n = b.size(0);
            TORCH_CHECK(b.size(1) == k, "ck_grouped_gemm: K mismatch at group ", i);
            stride_b = b.size(1); // K
        }
        else // 'R': b stored [K,N] row-major
        {
            TORCH_CHECK(b.size(0) == k, "ck_grouped_gemm: K mismatch at group ", i);
            n = b.size(1);
            stride_b = b.size(1); // N
        }
        stride_c = n;

        TORCH_CHECK(m > 0 && n > 0 && k > 0, "ck_grouped_gemm: all dimensions must be positive");
        check_supported_shape(dtype, m, n, k);
        TORCH_CHECK(m <= std::numeric_limits<int>::max() && n <= std::numeric_limits<int>::max() &&
                        k <= std::numeric_limits<int>::max(),
                    "ck_grouped_gemm: dimensions exceed int range expected by CK C ABI");

        torch::Tensor c;
        if(c_tensors_out != nullptr)
        {
            c = c_tensors_out->at(i);
            check_grouped_gemm_tensor(c, "c");
            TORCH_CHECK(c.device() == device,
                        "ck_grouped_gemm: all c tensors must be on the same device");
            TORCH_CHECK(c.scalar_type() == c_dtype,
                        "ck_grouped_gemm: c tensor dtype mismatch at group ", i);
            TORCH_CHECK(c.size(0) == m && c.size(1) == n,
                        "ck_grouped_gemm: c tensor shape mismatch at group ", i,
                        ", expected [", m, ", ", n, "]");
        }
        else
        {
            c = torch::empty({m, n}, torch::TensorOptions().dtype(c_dtype).device(device));
        }
        outputs.push_back(c);

        descs.push_back(ck_tile_hcu_grouped_gemm_desc{a.data_ptr(),
                                                      b.data_ptr(),
                                                      c.data_ptr(),
                                                      1,
                                                      static_cast<int>(m),
                                                      static_cast<int>(n),
                                                      static_cast<int>(k),
                                                      static_cast<int>(stride_a),
                                                      static_cast<int>(stride_b),
                                                      static_cast<int>(stride_c),
                                                      0,
                                                      nullptr,
                                                      nullptr});
    }

    const auto workspace_bytes =
        ck_tile_hcu_grouped_gemm_workspace_size(static_cast<int>(descs.size()), 0);
    auto workspace = grouped_gemm_workspace(device, static_cast<int64_t>(workspace_bytes));

    const hipStream_t stream = at::hip::getCurrentHIPStream();
    const int rc             = ck_tile_hcu_grouped_gemm_run(descs.data(),
                                                static_cast<int>(descs.size()),
                                                dtype_to_grouped_gemm_dtype(dtype),
                                                gemm_layout.a_layout,
                                                gemm_layout.b_layout,
                                                workspace.data_ptr(),
                                                stream);
    TORCH_CHECK(rc == 0, "ck_grouped_gemm: CK C ABI returned error ", rc);
    return outputs;
}

AITER_CPP_TORCH_API std::vector<torch::Tensor>
ck_grouped_gemm(std::vector<torch::Tensor>& a_tensors,
                std::vector<torch::Tensor>& b_tensors,
                const std::string& layout)
{
    return ck_grouped_gemm_impl(a_tensors, b_tensors, nullptr, layout);
}

AITER_CPP_TORCH_API std::vector<torch::Tensor>
ck_grouped_gemm_out(std::vector<torch::Tensor>& a_tensors,
                    std::vector<torch::Tensor>& b_tensors,
                    std::vector<torch::Tensor>& c_tensors,
                    const std::string& layout)
{
    return ck_grouped_gemm_impl(a_tensors, b_tensors, &c_tensors, layout);
}

} // namespace native
} // namespace aiter
