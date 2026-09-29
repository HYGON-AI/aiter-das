// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT
//
// blockwise_scaled_cast_transpose —— FP8/INT8 分块量化 + 转置 kernel。
//
// 功能：对连续输入 [M, K] 按 1×128（rowwise）/ 128×1（columnwise）分块计算 amax 与
// scale，把输入量化为 int8 / fp8(e4m3/e5m2)，可选同时产出转置输出（columnwise
// GEMM_READY，供 K×N GEMM 直接消费）与 COMPACT 布局（all-gather 就绪）。单次调用
// 产出双布局双 scale。算子说明与性能数据见 docs/blockwise_scaling_cast_transpose.md。
//
// 平台约定：
//   1) 命名空间 aiter::blockwise；launcher 形参 at::Tensor；纯 HIP API，
//      取流 at::hip::getCurrentHIPStream（与仓库内 cache_kernels.cu 等惯例一致）
//   2) fp8 类型使用 c10 的 at::Float8_e4m3fn/e5m2，不要用 arch 宏门控自定义
//      fp8 类型——arch 宏只注入 device 编译趟，host/device 两侧类型不一致会导致
//      运行期按符号名找不到 kernel（"Cannot find Symbol"）
//   3) aiter JIT 不比对源码修改时间：改本文件后必须 AITER_REBUILD=1 显式重编
//
// 关键设计 —— fp8 输出走硬件打包转换（性能关键）：
//   4 元素打包转换、一条 uint32 写出（写合并）：
//     gfx938    -> __builtin_hcu_cvt_pk_fp8_f32/bf8_f32 硬件指令（2 条 cvt/4 元素）
//     其他 arch -> 软件位操作 RNE 回退
//   实测（gfx938）：fp8 输出 case 提速 23%~43%，35 个对拍 case 全集几何平均 0.94
//   （优于 origin），全部数值组 atol=0 通过。
//   语义注记：硬件转换的舍入/饱和与 c10 RNE 在 NaN/e4m3fn-max/denormal 边界可能
//   不同（软件回退路径 NaN 饱和到 0x7e，c10 为 0x7f；对拍数值组输入无 NaN）。
//
// 行为契约（fail-fast，违反直接抛 RuntimeError）：
//   - block_len 仅支持 128
//   - output/scale_inv 的有无必须与 rowwise 一致、output_t/scale_inv_t 与 columnwise 一致
//   - 仅 columnwise（无 rowwise 输出）时跳过两个输出的 dtype 一致性比较
//     （此时 output 为空，不可解引用）
//   - 输入与有值输出必须连续（避免静默按连续解释造成越界读写）
//   - 共享内存 < 48KB 不调用 hipFuncSetAttribute；调用则检查返回值
//   - int8 输出路径为饱和舍入，scale/amax 计算与 fp 路径共用

#include "blockwise_scaled_cast_transpose.h"


namespace aiter {
namespace blockwise {


constexpr size_t kThreadsPerWarp = 64;

// Hyperparameters for performance tuning
constexpr int kTileDim64 = 64;
constexpr int kTileDim = 128;  // Fixed to 128 beacause we are using 1x128 and 128x1 quantization
constexpr int kNVecIn = 8;     // The number of elements each LDG touches
constexpr int kNVecOut = 16;   // The number of elements each STG touches
constexpr int kNVecSMem = 4;   // The number of elements each LDS/STS touches
constexpr int kThreadsPerBlock = 512;  // Thread block size, 8 warps in total

// Auto-calculated constants, do not modify directly)
static_assert(kNVecIn % kNVecSMem == 0, "kNVecIn must be divisible by kNVecSMem");
static_assert(kNVecOut % kNVecSMem == 0, "kNVecOut must be divisible by kNVecSMem");
constexpr int kSMemRow = kTileDim64;
constexpr int kSMemCol = (kTileDim / kNVecSMem) ;
constexpr int kSMemSize = kSMemRow * kSMemCol * kNVecSMem;
constexpr int kNumThreadsLoad = kTileDim / kNVecIn;
constexpr int kNumThreadsStore = kTileDim / kNVecOut;
static_assert(kNumThreadsLoad <= kThreadsPerWarp, "kNumThreadsLoad must be <= kThreadsPerWarp");
static_assert(kNumThreadsStore <= kThreadsPerWarp, "kNumThreadsStore must be <= kThreadsPerWarp");
constexpr int kNumWarps = kThreadsPerBlock / kThreadsPerWarp;




constexpr int kFP32SMemCol = kTileDim / kNVecSMem;
constexpr int kFP32SMemSize = kSMemRow * kFP32SMemCol * kNVecSMem;

// ---------------------------------------------------------------------------
// fp8 硬件打包转换设施：4 元素打包 -> 一条 uint32 写出
//（kNVecOut=16 = 4 组，与打包粒度整除）。
// ---------------------------------------------------------------------------
static_assert(sizeof(at::Float8_e4m3fn) == 1 && sizeof(at::Float8_e5m2) == 1,
              "fp8 packed store assumes 1-byte fp8 element");

__device__ __forceinline__ uint8_t d6c_fp8_e4m3_sw(float f)
{
    constexpr uint32_t fp8_max    = UINT32_C(1087) << 20;
    constexpr uint32_t denorm_mask = UINT32_C(141) << 23;
    uint32_t f_bits                = __builtin_bit_cast(uint32_t, f);
    uint8_t result                 = 0u;
    const uint32_t sign            = f_bits & UINT32_C(0x80000000);
    f_bits ^= sign;
    if(f_bits >= fp8_max)
    {
        result = UINT8_C(0x7e);
    }
    else
    {
        if(f_bits < (UINT32_C(121) << 23))
        {
            f_bits = __builtin_bit_cast(
                uint32_t, __builtin_bit_cast(float, f_bits) + __builtin_bit_cast(float, denorm_mask));
            result = static_cast<uint8_t>(f_bits - denorm_mask);
        }
        else
        {
            uint8_t mant_odd = (f_bits >> 20) & 1;
            f_bits += ((uint32_t)(7 - 127) << 23) + 0xFFFFF;
            f_bits += mant_odd;
            result = static_cast<uint8_t>(f_bits >> 20);
            if(result > UINT8_C(0x7e))
                result = UINT8_C(0x7e);
        }
    }
    result |= static_cast<uint8_t>(sign >> 24);
    return result;
}

__device__ __forceinline__ uint8_t d6c_fp8_e5m2_sw(float f)
{
    constexpr uint32_t fp8_max    = UINT32_C(143) << 23;
    constexpr uint32_t denorm_mask = UINT32_C(134) << 23;
    constexpr uint32_t fp32_inf    = UINT32_C(255) << 23;
    uint32_t f_bits                = __builtin_bit_cast(uint32_t, f);
    uint8_t result                 = 0u;
    const uint32_t sign            = f_bits & UINT32_C(0x80000000);
    f_bits ^= sign;
    if(f_bits >= fp8_max)
    {
        result = f_bits > fp32_inf ? UINT8_C(0x7F) : UINT8_C(0x7C);
    }
    else
    {
        if(f_bits < (UINT32_C(113) << 23))
        {
            f_bits = __builtin_bit_cast(
                uint32_t, __builtin_bit_cast(float, f_bits) + __builtin_bit_cast(float, denorm_mask));
            result = static_cast<uint8_t>(f_bits - denorm_mask);
        }
        else
        {
            uint32_t mant_odd = (f_bits >> 21) & 1;
            f_bits += ((uint32_t)(15 - 127) << 23) + 0xFFFFF;
            f_bits += mant_odd;
            result = static_cast<uint8_t>(f_bits >> 21);
        }
    }
    result |= static_cast<uint8_t>(sign >> 24);
    return result;
}

template <bool kE4M3>
__device__ __forceinline__ uint32_t d6c_fp8_x4(float a, float b, float c, float d)
{
#if defined(__gfx938__)
    // 硬件 packed：2 条 cvt 指令产出 4 元素
    uint32_t res;
    if constexpr(kE4M3)
    {
        res = __builtin_hcu_cvt_pk_fp8_f32(a, b, 0u, false);
        res = __builtin_hcu_cvt_pk_fp8_f32(c, d, res, true);
    }
    else
    {
        res = __builtin_hcu_cvt_pk_bf8_f32(a, b, 0u, false);
        res = __builtin_hcu_cvt_pk_bf8_f32(c, d, res, true);
    }
    return res;
#else
    // 非 gfx938：软件 RNE 回退（打包写不变）
    uint32_t out;
    uint8_t* p = reinterpret_cast<uint8_t*>(&out);
    if constexpr(kE4M3)
    {
        p[0] = d6c_fp8_e4m3_sw(a);
        p[1] = d6c_fp8_e4m3_sw(b);
        p[2] = d6c_fp8_e4m3_sw(c);
        p[3] = d6c_fp8_e4m3_sw(d);
    }
    else
    {
        p[0] = d6c_fp8_e5m2_sw(a);
        p[1] = d6c_fp8_e5m2_sw(b);
        p[2] = d6c_fp8_e5m2_sw(c);
        p[3] = d6c_fp8_e5m2_sw(d);
    }
    return out;
#endif
}

// 4 个已缩放 float -> 打包写 4 个连续 fp8 elt（dst4 须 4B 对齐，elt 数组内连续）
template <typename OType>
__device__ __forceinline__ void d6c_fp8_packed(float s0, float s1, float s2, float s3, OType* dst4)
{
    constexpr bool kE4M3 = std::is_same_v<OType, at::Float8_e4m3fn>;
    static_assert(std::is_same_v<OType, at::Float8_e4m3fn> || std::is_same_v<OType, at::Float8_e5m2>,
                  "fp8 path requires c10 fp8 output type");
    *reinterpret_cast<uint32_t*>(dst4) = d6c_fp8_x4<kE4M3>(s0, s1, s2, s3);
}

// 同上，源为同一 vec 内连续 4 元素（rowwise 用）
template <typename OType, typename IType>
__device__ __forceinline__ void d6c_fp8_packed_vec(const IType* v4, OType* dst4, float scale)
{
    d6c_fp8_packed<OType>(static_cast<float>(v4[0]) * scale, static_cast<float>(v4[1]) * scale,
                          static_cast<float>(v4[2]) * scale, static_cast<float>(v4[3]) * scale, dst4);
}

template <bool kAligned, typename CType, typename IType, typename OType>
__global__ void __launch_bounds__(kThreadsPerBlock) block_scaled_1d_cast_transpose_kernel_rowwise(
    const IType* const input, OType* const output_c,
    CType* const tile_scales_inv_c, const size_t row_length,
    const size_t num_rows, const size_t scale_stride_x, const size_t scale_stride_y,
    const float epsilon,FP8BlockwiseRowwiseOption rowwise_option,
    const bool pow_2_scaling) {
  bool return_rowwise = rowwise_option != FP8BlockwiseRowwiseOption::NONE;

  using SMemVec = Vec<IType, kNVecSMem>;
  using OVec = Vec<OType, kNVecOut>;
  union IVec {
    Vec<IType, kNVecIn> input_type;
    Vec<SMemVec, kNVecIn / kNVecSMem> smem_type;
  };

  extern __shared__ char smem_base[];
  SMemVec* smem = reinterpret_cast<SMemVec*>(smem_base);
  // Step 1: Load input to shared memory
  {
    constexpr int r_stride = kThreadsPerBlock / kNumThreadsLoad;  // stride in rows of shared memory
    constexpr int num_iterations = kTileDim64 / r_stride;//64/16=4
    const int c_s =
        (threadIdx.x % kNumThreadsLoad) * (kNVecIn / kNVecSMem);  // Column in shared memory
    int r_s = threadIdx.x / kNumThreadsLoad;                      // Row in shared memory
    const size_t c_g =
        static_cast<size_t>(blockIdx.x) * kTileDim + c_s * kNVecSMem;    // Column in global memory
    size_t r_g = static_cast<size_t>(blockIdx.y) * kTileDim64 + r_s;       // Row in global memory
    const size_t stride_g = static_cast<size_t>(r_stride) * row_length;  // Stride in global memory
    const size_t num_ele = c_g < row_length ? std::min(static_cast<size_t>(kNVecIn), row_length - c_g)
                                            : 0;            // For not aligned case
    const IType* input_g = &input[r_g * row_length + c_g];  // Input address in global memory
#pragma unroll
    for (int iter = 0; iter < num_iterations; ++iter) {
      IVec input_vec;
      // Step 1.1: Load from global memory (input) to registers
      if constexpr (kAligned) {
        input_vec.input_type.load_from(input_g);
      } else {
        if (r_g < num_rows) {
          input_vec.input_type.load_from_elts(input_g, 0, num_ele);
        } else {
          input_vec.input_type.clear();
        }
      }
      // Step 1.2: Write to shared memory - row Major
#pragma unroll
      for (int i = 0; i < kNVecIn / kNVecSMem; ++i) {
        int c = c_s + i;
        int r = r_s;
        // row Major Store
       smem[r * kSMemCol + c] = input_vec.smem_type.data.elt[i];
      }
      // Step 1.3: Update input address, row index of shared memory, (and row index of global memory for not aligned case)
      input_g += stride_g;
      r_s += r_stride;
      if constexpr (!kAligned) {
        r_g += r_stride;
      }
    }
  }

  __syncthreads();

  // Step 2: Cast and store to output_c
  if (return_rowwise) {
    constexpr int r_stride =
        kThreadsPerBlock / kNumThreadsStore;  // stride in rows of shared memory
    constexpr int num_iterations = kTileDim64 / r_stride;
    const int c_s =
        (threadIdx.x % kNumThreadsStore) * (kNVecOut / kNVecSMem);  // Column in shared memory
    int r_s = threadIdx.x / kNumThreadsStore;                       // Row in shared memory
    const size_t c_g =
        static_cast<size_t>(blockIdx.x) * kTileDim + c_s * kNVecSMem;    // Column in global memory
    size_t r_g = static_cast<size_t>(blockIdx.y) * kTileDim64 + r_s;       // Row in global memory
    const size_t stride_g = static_cast<size_t>(r_stride) * row_length;  // Stride in global memory
    const size_t num_ele = c_g < row_length ? std::min(static_cast<size_t>(kNVecOut), row_length - c_g)
                                            : 0;          // For not aligned case
    OType* output_g = &output_c[r_g * row_length + c_g];  // Output address in global memory
    // Each kNumThreadsStore threads form a warp process one row, we need to find the lane id of
    // the first thread to do the reduction.
    const unsigned src_lane = (threadIdx.x % kThreadsPerWarp) / kNumThreadsStore * kNumThreadsStore;
    // This mask represents which threads should do the reduction together.
    const unsigned mask = ((1 << kNumThreadsStore) - 1) << src_lane;
    const bool is_src_lane = (threadIdx.x % kNumThreadsStore) == 0;

#pragma unroll
    for (int iter = 0; iter < num_iterations; ++iter) {
      SMemVec smem_vec[kNVecOut / kNVecSMem];
      // Step 2.1: Load from shared memory to registers - Column Major
#pragma unroll
      for (int i = 0; i < kNVecOut / kNVecSMem; ++i) {
        int c = c_s + i;
        int r = r_s;
        // Column Major Read
        smem_vec[i] = smem[r * kSMemCol + c];
      }

      // Step 2.2: Compute local amax
      CType amax = 0;
#pragma unroll
      for (int i = 0; i < kNVecOut / kNVecSMem; ++i) {
#pragma unroll
        for (int j = 0; j < kNVecSMem; ++j) {
          __builtin_assume(amax >= 0);
          amax = fmaxf(amax, fabsf(smem_vec[i].data.elt[j]));
        }
      }

      // Step 2.3: Reduce amax
#pragma unroll
      for (int delta = kNumThreadsStore / 2; delta > 0; delta /= 2) {

        //const float other_amax =__shfl_xor_sync((unsigned long long)(mask), amax, delta, kThreadsPerWarp);
        const float other_amax =__shfl_xor( amax, delta, kThreadsPerWarp);
        __builtin_assume(amax >= 0);
        __builtin_assume(other_amax >= 0);

        amax = fmaxf(amax, other_amax);
      }

      CType scale;
      // Step 2.4: Compute scale
      scale = compute_scale_from_types<IType, OType>(amax, epsilon, pow_2_scaling);
      // Step 2.5: Write scale_inv
      bool write_scale_inv = is_src_lane;
      if constexpr (!kAligned) {
        write_scale_inv &= (r_g < num_rows);
      }
      if (write_scale_inv) {
        CType scale_inv = 1.0 / scale;
        size_t row_idx = static_cast<size_t>(blockIdx.y) * kTileDim64 + r_s;//
        size_t col_idx = static_cast<size_t>(blockIdx.x);
        tile_scales_inv_c[row_idx * scale_stride_y + col_idx * scale_stride_x] = scale_inv;
      }
      // Step 2.6: Quantize
      OVec output_vec;
      if constexpr (std::is_same_v<OType, int8_t>) {
#pragma unroll
        for (int i = 0; i < kNVecOut / kNVecSMem; ++i) {
#pragma unroll
          for (int j = 0; j < kNVecSMem; ++j) {
            output_vec.data.elt[i * kNVecSMem + j] = static_cast<OType>(lroundf(fmaxf(
                -127.0f, fminf(127.0f, static_cast<CType>(smem_vec[i].data.elt[j]) * scale))));
          }
        }
      } else {
        // fp8：4 元素打包成一条 uint32 写出（组内元素连续，kNVecSMem=4 恰为一包）
#pragma unroll
        for (int i = 0; i < kNVecOut / kNVecSMem; ++i) {
          d6c_fp8_packed_vec<OType>(smem_vec[i].data.elt, output_vec.data.elt + i * kNVecSMem, scale);
        }
      }
      // Step 2.7: Store output_c
      if constexpr (kAligned) {
        output_vec.store_to(output_g);
      } else {
        if (r_g < num_rows) {
          output_vec.store_to_elts(output_g, 0, num_ele);
        }
      }
      // Step 2.8: Update output address, row index of shared memory (and row index of global memory for not aligned case)
      output_g += stride_g;
      r_s += r_stride;
      if constexpr (!kAligned) {
        r_g += r_stride;
      }
    }
  }


}

constexpr int kTileDim64_Colwise=64;
constexpr int kNVecSMem_Colwise = 2;
constexpr int kSMemRow_Colwise = kTileDim;
constexpr int kSMemCol_Colwise = (kTileDim64_Colwise / kNVecSMem_Colwise) ;
constexpr int kSMemSize_Colwise = kSMemRow_Colwise * kSMemCol_Colwise * kNVecSMem_Colwise;
constexpr int kNumThreadsLoad_Colwise = kTileDim64_Colwise / kNVecIn;
constexpr int kNumThreadsStore_Colwise = kTileDim / kNVecOut;
constexpr int kThreadsPerBlock_Colwise =256;
constexpr int kNumWarps_Colwise=kThreadsPerBlock_Colwise/kThreadsPerWarp;

template <bool kAligned, typename CType, typename IType, typename OType>
__global__ void __launch_bounds__(kThreadsPerBlock_Colwise) block_scaled_1d_cast_transpose_kernel_colwise(
    const IType* const input,  OType* const output_t, CType* const tile_scales_inv_t, const size_t row_length,
    const size_t num_rows,  const size_t scale_t_stride_x, const size_t scale_t_stride_y, const float epsilon,
   FP8BlockwiseColumnwiseOption columnwise_option,const bool pow_2_scaling) {


  bool return_columnwise_gemm_ready =
      columnwise_option == FP8BlockwiseColumnwiseOption::COLUMNWISE_GEMM_READY;
  bool return_columnwise_compact =
      columnwise_option == FP8BlockwiseColumnwiseOption::COLUMNWISE_COMPACT;

  using SMemVec = Vec<IType, kNVecSMem_Colwise>;
  using OVec = Vec<OType, kNVecOut>;
  union IVec {
    Vec<IType, kNVecIn> input_type;
    Vec<SMemVec, kNVecIn / kNVecSMem_Colwise> smem_type;
  };

  extern __shared__ char smem_base[];
  SMemVec* smem = reinterpret_cast<SMemVec*>(smem_base);
  // Step 1: Load input to shared memory
  {
    constexpr int r_stride = kThreadsPerBlock_Colwise / kNumThreadsLoad_Colwise;  // stride in rows of shared memory
    constexpr int num_iterations = kTileDim / r_stride;
    const int c_s =
        (threadIdx.x % kNumThreadsLoad_Colwise) * (kNVecIn / kNVecSMem_Colwise);  // Column in shared memory
    int r_s = threadIdx.x / kNumThreadsLoad_Colwise;                      // Row in shared memory
    const size_t c_g =
        static_cast<size_t>(blockIdx.x) * kTileDim64_Colwise + c_s * kNVecSMem_Colwise;    // Column in global memory
    size_t r_g = static_cast<size_t>(blockIdx.y) * kTileDim + r_s;       // Row in global memory
    const size_t stride_g = static_cast<size_t>(r_stride) * row_length;  // Stride in global memory
    const size_t num_ele = c_g < row_length ? std::min(static_cast<size_t>(kNVecIn), row_length - c_g)
                                            : 0;            // For not aligned case
    const IType* input_g = &input[r_g * row_length + c_g];  // Input address in global memory
#pragma unroll
    for (int iter = 0; iter < num_iterations; ++iter) {
      IVec input_vec;
      // Step 1.1: Load from global memory (input) to registers
      if constexpr (kAligned) {
        input_vec.input_type.load_from(input_g);
      } else {
        if (r_g < num_rows) {
          input_vec.input_type.load_from_elts(input_g, 0, num_ele);
        } else {
          input_vec.input_type.clear();
        }
      }
      // Step 1.2: Write to shared memory - Row Major
#pragma unroll
      for (int i = 0; i < kNVecIn / kNVecSMem_Colwise; ++i) {
        int c = c_s + i;
        int r = r_s;
        // Row Major Store
        smem[r * kSMemCol_Colwise + c] = input_vec.smem_type.data.elt[i];
      }
      // Step 1.3: Update input address, row index of shared memory, (and row index of global memory for not aligned case)
      input_g += stride_g;
      r_s += r_stride;
      if constexpr (!kAligned) {
        r_g += r_stride;
      }
    }
  }

  __syncthreads();

  // Step 3: Transpose, cast and store to output_t
  if (return_columnwise_gemm_ready) {
    constexpr int c_stride =
        kThreadsPerBlock_Colwise / kNumThreadsStore_Colwise;  // Stride in columns of shared memory
    constexpr int num_iterations = kTileDim64_Colwise / (c_stride * kNVecSMem_Colwise);
    const int r_s = (threadIdx.x % kNumThreadsStore_Colwise) * kNVecOut;  // Row in shared memory
    int c_s = threadIdx.x / kNumThreadsStore_Colwise;                     // Column in shared memory
    size_t r_g =
        static_cast<size_t>(blockIdx.x) * kTileDim64_Colwise + c_s * kNVecSMem_Colwise;     // Row in global memory
    const size_t c_g = static_cast<size_t>(blockIdx.y) * kTileDim + r_s;  // Column in global memory
    const size_t stride_g =
        static_cast<size_t>(c_stride) * kNVecSMem_Colwise * num_rows;  // Stride in global memory
    const size_t num_ele = c_g < num_rows ? std::min(static_cast<size_t>(kNVecOut), num_rows - c_g)
                                          : 0;          // For not aligned case
    OType* output_g = &output_t[r_g * num_rows + c_g];  // Output address in global memory
    // Each kNumThreadsStore threads form a warp process one row, we need to find the lane id of
    // the first thread to do the reduction.
    const unsigned src_lane = (threadIdx.x % kThreadsPerWarp) / kNumThreadsStore_Colwise * kNumThreadsStore_Colwise;
    // This mask represents which threads should do the reduction together.
    const unsigned mask = ((1 << kNumThreadsStore_Colwise) - 1) << src_lane;
    const bool is_src_lane = (threadIdx.x % kNumThreadsStore_Colwise) == 0;
#pragma unroll
    for (int iter = 0; iter < num_iterations; ++iter) {
      SMemVec smem_vec[kNVecOut];
      // Step 3.1: Load from shared memory to registers - Column Major
#pragma unroll
      for (int i = 0; i < kNVecOut; ++i) {
        int r = r_s + i;
        int c = c_s;
        // Row Major Read
        smem_vec[i] = smem[r * kSMemCol_Colwise + c];
      }
#pragma unroll
      for (int smem_idx = 0; smem_idx < kNVecSMem_Colwise; ++smem_idx) {
        // Step 3.2: Compute local amax
        CType amax = 0;
#pragma unroll
        for (int i = 0; i < kNVecOut; ++i) {
          amax = fmaxf(amax, fabsf(smem_vec[i].data.elt[smem_idx]));
        }
        // Step 3.3: Reduce amax
#pragma unroll
        for (int delta = kNumThreadsStore_Colwise / 2; delta > 0; delta /= 2) {

          // const float other_amax =
          //     __shfl_xor_sync((unsigned long long)(mask), amax, delta, kThreadsPerWarp);
          const float other_amax =__shfl_xor( amax, delta, kThreadsPerWarp);

          __builtin_assume(amax >= 0);
          __builtin_assume(other_amax >= 0);
          amax = fmaxf(amax, other_amax);
        }

        // Step 3.4: Compute scale
        CType scale;
        scale = compute_scale_from_types<IType, OType>(amax, epsilon, pow_2_scaling);
        // Step 3.5: Write scale_inv_t
        bool write_scale_inv = is_src_lane;
        if constexpr (!kAligned) {
          write_scale_inv &= (r_g + smem_idx < row_length);
        }
        if (write_scale_inv) {
          CType scale_inv = 1.0 / scale;
          size_t row_idx = static_cast<size_t>(blockIdx.x) * kTileDim64_Colwise + c_s * kNVecSMem_Colwise + smem_idx;
          size_t col_idx = static_cast<size_t>(blockIdx.y);
          tile_scales_inv_t[row_idx * scale_t_stride_y + col_idx * scale_t_stride_x] = scale_inv;
        }
        // Step 3.6: Quantize
        OVec output_vec;
        if constexpr (std::is_same_v<OType, int8_t>) {
#pragma unroll
          for (int i = 0; i < kNVecOut; ++i) {
            output_vec.data.elt[i] = static_cast<OType>(lroundf(
                fmaxf(-127.0f,
                      fminf(127.0f, static_cast<CType>(smem_vec[i].data.elt[smem_idx]) * scale))));
          }
        } else {
          // fp8：跨 vec 同偏移取 4 元素打包写出
#pragma unroll
          for (int g = 0; g < kNVecOut / 4; ++g) {
            const float s0 = static_cast<CType>(smem_vec[g * 4 + 0].data.elt[smem_idx]) * scale;
            const float s1 = static_cast<CType>(smem_vec[g * 4 + 1].data.elt[smem_idx]) * scale;
            const float s2 = static_cast<CType>(smem_vec[g * 4 + 2].data.elt[smem_idx]) * scale;
            const float s3 = static_cast<CType>(smem_vec[g * 4 + 3].data.elt[smem_idx]) * scale;
            d6c_fp8_packed<OType>(s0, s1, s2, s3, output_vec.data.elt + g * 4);
          }
        }
        // Step 3.7: Store output_t
        if constexpr (kAligned) {
          output_vec.store_to(output_g + smem_idx * num_rows);
        } else {
          if (r_g + smem_idx < row_length) {
            output_vec.store_to_elts(output_g + smem_idx * num_rows, 0, num_ele);
          }
        }
      }
      // Step 3.8: Update output address, column index of shared memory (and row index of global memory for not aligned case)
      output_g += stride_g;
      c_s += c_stride;
      if constexpr (!kAligned) {
        r_g += c_stride * kNVecSMem_Colwise;
      }
    }
  }


  if (return_columnwise_compact) {
    // thread tile should be 4x16, 16 means 8 smem reads
    constexpr int kThreadTileRow = kTileDim / kThreadsPerWarp;
    constexpr int kThreadTileCol = kNVecOut;
    using RegVec = Vec<IType, kThreadTileCol>;
    using RegScaleVec = Vec<CType, kThreadTileCol>;//float,16
    constexpr int num_smem_reads = kNVecOut / kNVecSMem_Colwise;
    // c_stride will not be used here because we only have one iteration
    // constexpr int c_stride = kThreadTileCol * kNumWarps / kNVecSMem;
    constexpr int num_iterations =
        kTileDim64_Colwise / (kNumWarps_Colwise * kThreadTileCol);  // should be only one iteration
    static_assert(num_iterations == 1,
                  "num_iterations should be 1 for columnwise non-transpose case");
    const int thr_idx_in_warp = threadIdx.x % kThreadsPerWarp;
    const int warp_idx = threadIdx.x / kThreadsPerWarp;
    const int r_s = thr_idx_in_warp * kThreadTileRow;               // Row in shared memory
    int c_s = warp_idx * num_smem_reads;                            // Column in shared memory
    size_t r_g = static_cast<size_t>(blockIdx.y) * kTileDim + r_s;  // Row in global memory
    const size_t c_g =
        static_cast<size_t>(blockIdx.x) * kTileDim64_Colwise + c_s * kNVecSMem_Colwise;  // Column in global memory
    const size_t num_ele = c_g < row_length
                               ? std::min(static_cast<size_t>(kThreadTileCol), row_length - c_g)
                               : 0;  // For not aligned case
#pragma unroll
    for (int iter = 0; iter < num_iterations; ++iter) {
      RegVec reg_vec[kThreadTileRow];
      RegScaleVec thr_scale;

      // Step 3.1: Load from shared memory to registers
#pragma unroll
      for (int i = 0; i < kThreadTileRow; ++i) {
        int r = r_s + i;
#pragma unroll
        for (int j = 0; j < num_smem_reads; ++j) {
          int c = c_s + j;
          SMemVec smem_vec = smem[r * kSMemCol_Colwise + c];
          // copy smem_vec to reg vec with its elements
#pragma unroll
          for (int k = 0; k < kNVecSMem_Colwise; ++k) {
            reg_vec[i].data.elt[j * kNVecSMem_Colwise + k] = smem_vec.data.elt[k];
          }
        }
      }
#pragma unroll
      for (int reg_idx = 0; reg_idx < kThreadTileCol; ++reg_idx) {
        // Step 3.2: Compute local amax
        CType amax = 0;
#pragma unroll
        for (int i = 0; i < kThreadTileRow; ++i) {
          amax = fmaxf(amax, fabsf(reg_vec[i].data.elt[reg_idx]));
        }
        // Step 3.3: Reduce amax
        const bool is_src_lane = thr_idx_in_warp == 0;
#pragma unroll
        for (int delta = kThreadsPerWarp / 2; delta > 0; delta /= 2) {

          // const float other_amax =
          //     __shfl_xor_sync((unsigned long long)(0xFFFFFFFF), amax, delta, kThreadsPerWarp);
          const float other_amax =__shfl_xor( amax, delta, kThreadsPerWarp);

          __builtin_assume(amax >= 0);
          __builtin_assume(other_amax >= 0);
          amax = fmaxf(amax, other_amax);
        }
        // Step 3.4: Compute scale
        CType scale;
        scale = compute_scale_from_types<IType, OType>(amax, epsilon, pow_2_scaling);
        thr_scale.data.elt[reg_idx] = scale;
        // Step 3.5: Write scale_inv_t
        bool write_scale_inv = is_src_lane;
        if constexpr (!kAligned) {
          write_scale_inv &= (c_g + reg_idx < row_length);
        }
        if (write_scale_inv) {
          CType scale_inv = 1.0 / scale;
          size_t row_idx = static_cast<size_t>(blockIdx.y);
          size_t col_idx = static_cast<size_t>(blockIdx.x) * kTileDim64_Colwise + c_s * kNVecSMem_Colwise + reg_idx;
          tile_scales_inv_t[row_idx * scale_t_stride_y + col_idx * scale_t_stride_x] = scale_inv;
        }
      }
      // Step 3.6: Quantize
      for (int row_idx = 0; row_idx < kThreadTileRow; ++row_idx) {
        OType* output_g =
            &output_t[(r_g + row_idx) * row_length + c_g];  // Output address in global memory
        OVec output_vec;
        if constexpr (std::is_same_v<OType, int8_t>) {
#pragma unroll
          for (int i = 0; i < kThreadTileCol; ++i) {
            output_vec.data.elt[i] = static_cast<OType>(lroundf(
                fmaxf(-127.0f,
                      fminf(127.0f, static_cast<CType>(reg_vec[row_idx].data.elt[i]) * thr_scale.data.elt[i]))));
          }
        } else {
          // fp8（compact）：scale 逐元素生效，先缩放再 4 元素打包
#pragma unroll
          for (int g = 0; g < kThreadTileCol / 4; ++g) {
            const float s0 = static_cast<CType>(reg_vec[row_idx].data.elt[g * 4 + 0]) * thr_scale.data.elt[g * 4 + 0];
            const float s1 = static_cast<CType>(reg_vec[row_idx].data.elt[g * 4 + 1]) * thr_scale.data.elt[g * 4 + 1];
            const float s2 = static_cast<CType>(reg_vec[row_idx].data.elt[g * 4 + 2]) * thr_scale.data.elt[g * 4 + 2];
            const float s3 = static_cast<CType>(reg_vec[row_idx].data.elt[g * 4 + 3]) * thr_scale.data.elt[g * 4 + 3];
            d6c_fp8_packed<OType>(s0, s1, s2, s3, output_vec.data.elt + g * 4);
          }
        }
        // Step 3.7: Store output_t
        if constexpr (kAligned) {
          output_vec.store_to(output_g);
        } else {
          if (r_g + row_idx < num_rows) {
            output_vec.store_to_elts(output_g, 0, num_ele);
          }
        }
      }
      // Step 3.8: Update output address, column index of shared memory
      // this section shouldn't matter since we only have one iteration
    }
  }

}


void blockwise_scaled_1d_cast_transpose(const at::Tensor& input,std::optional<at::Tensor> output,std::optional<at::Tensor> scale_inv,
                                        std::optional<at::Tensor> output_transpose,std::optional<at::Tensor> scale_inv_transpose,
                                        const int block_len,const bool rowwise,const bool columnwise,const float epsilon,
                                        const bool pow2_scale,const bool all_gather_usage, at::ScalarType out_dtype) {

  const size_t row_length = input.sizes().size() > 0 ? input.sizes().at(input.sizes().size() - 1) : 1u;
  size_t num_elements = row_length;
  size_t num_rows = 1;
  for (size_t i = 0; (i < input.sizes().size() - 1) && (input.sizes().size() > 0); ++i) {
    num_rows *= input.sizes().at(i);
    num_elements *= input.sizes().at(i);
  }

  // Early return if the input tensor is empty
  if (num_elements == 0) {
    return;
  }

  // 校验：rowwise/columnwise 标志必须与对应输出实参的有无一致
  TORCH_CHECK(output.has_value() == rowwise,
              "blockwise_scaled_cast_transpose: rowwise flag (", rowwise,
              ") mismatch with output presence (", output.has_value(), ")");
  TORCH_CHECK(output_transpose.has_value() == columnwise,
              "blockwise_scaled_cast_transpose: columnwise flag (", columnwise,
              ") mismatch with output_transpose presence (", output_transpose.has_value(), ")");

  // 校验：输入/输出必须连续，不连续直接报错（避免静默按连续解释出错）
  TORCH_CHECK(input.is_contiguous(), "blockwise_scaled_cast_transpose: input must be contiguous");
  if (output.has_value()) {
    TORCH_CHECK(output->is_contiguous(), "blockwise_scaled_cast_transpose: output must be contiguous");
  }
  if (scale_inv.has_value()) {
    TORCH_CHECK(scale_inv->is_contiguous(), "blockwise_scaled_cast_transpose: scale_inv must be contiguous");
  }
  if (output_transpose.has_value()) {
    TORCH_CHECK(output_transpose->is_contiguous(), "blockwise_scaled_cast_transpose: output_transpose must be contiguous");
  }
  if (scale_inv_transpose.has_value()) {
    TORCH_CHECK(scale_inv_transpose->is_contiguous(), "blockwise_scaled_cast_transpose: scale_inv_transpose must be contiguous");
  }

  // Options for scale layout of cuBLAS GEMM kernel.
  size_t scale_stride_x = 0;
  size_t scale_stride_y = 0;
  size_t scale_t_stride_x = 0;
  size_t scale_t_stride_y = 0;

  FP8BlockwiseRowwiseOption rowwise_option = FP8BlockwiseRowwiseOption::NONE;

  FP8BlockwiseColumnwiseOption columnwise_option = FP8BlockwiseColumnwiseOption::NONE;
  if (output.has_value()) {

        rowwise_option = all_gather_usage ? FP8BlockwiseRowwiseOption::ROWWISE_COMPACT
                                         : FP8BlockwiseRowwiseOption::ROWWISE_GEMM_READY;
  }
  if (output_transpose.has_value()) {

        columnwise_option = all_gather_usage
                            ? FP8BlockwiseColumnwiseOption::COLUMNWISE_COMPACT
                            : FP8BlockwiseColumnwiseOption::COLUMNWISE_GEMM_READY;
  }

  if (rowwise_option != FP8BlockwiseRowwiseOption::NONE) {
    TORCH_CHECK(rowwise_option == FP8BlockwiseRowwiseOption::ROWWISE_GEMM_READY ||
                   rowwise_option == FP8BlockwiseRowwiseOption::ROWWISE_COMPACT,
               "Unexpected rowwise enum value");
    TORCH_CHECK(input.sizes() == output.value().sizes(), "Input and output must have the same shape.");
    TORCH_CHECK(scale_inv.value().sizes().size() == 2, "Scale dimension must be 2.");
    size_t scale_k = scale_inv.value().sizes()[1];
    bool rowwise_compact = rowwise_option == FP8BlockwiseRowwiseOption::ROWWISE_COMPACT;
    scale_stride_x = rowwise_compact ? 1 : scale_k;
    scale_stride_y = rowwise_compact ? scale_k : 1;
  }

  if (columnwise_option != FP8BlockwiseColumnwiseOption::NONE) {
    TORCH_CHECK(output_transpose.value().sizes().size() == input.sizes().size(),
               "output_transpose must have same number of dimensions as input.");

    if (output_transpose.value().sizes().size() > 0) {
      if (columnwise_option == FP8BlockwiseColumnwiseOption::COLUMNWISE_GEMM_READY) {

        TORCH_CHECK(output_transpose.value().sizes()[0] == row_length, "Wrong dimension 0 of output_transpose.");
        for (size_t i = 1; i < output_transpose.value().sizes().size(); ++i) {
          TORCH_CHECK(output_transpose.value().sizes().at(i) == input.sizes().at(i - 1), "Wrong dimension in output_transpose");
        }
      } else {
        TORCH_CHECK(columnwise_option == FP8BlockwiseColumnwiseOption::COLUMNWISE_COMPACT,
                   "Unexpected columnwise option enum value");
        TORCH_CHECK(output_transpose.value().sizes()[0] == input.sizes()[0], "Wrong dimension 0 of output_transpose.");
        TORCH_CHECK(
            input.sizes() == output_transpose.value().sizes(),
            "Input and output_transpose must have the same shape for columnwise non-transpose case.");
      }
    }

    // 校验：仅在同时有 rowwise 输出时比较两个输出的 dtype
    //（仅 columnwise 时 output 为空，不可解引用）
    if (output.has_value()) {
      TORCH_CHECK(output.value().scalar_type() == output_transpose.value().scalar_type(), "output and output_transpose need to have the same dtype.");
    }
    TORCH_CHECK(scale_inv_transpose.value().sizes().size() == 2, "Scale_t dimension must be 2.");
    bool columnwise_compact = columnwise_option == FP8BlockwiseColumnwiseOption::COLUMNWISE_COMPACT;
    size_t scale_t_k = scale_inv_transpose.value().sizes()[1];
    scale_t_stride_x = columnwise_compact ? 1 : scale_t_k;
    scale_t_stride_y = columnwise_compact ? scale_t_k : 1;
  }

  const size_t num_blocks_x = DIVUP(row_length, (size_t)block_len);
  const size_t num_blocks_y = DIVUP(num_rows, (size_t)(block_len/2));

  TRANSFORMER_ENGINE_TYPE_SWITCH_INPUT(
      input.scalar_type(), InputType,

      TRANSFORMER_ENGINE_TYPE_SWITCH_8BIT(
          out_dtype, OutputType,

          dim3 grid(num_blocks_x, num_blocks_y, 1);

          const bool full_tile = row_length % block_len == 0 && num_rows % block_len == 0;

          TRANSFORMER_ENGINE_SWITCH_CONDITION(
              full_tile, kAligned,
              {
                // 校验：block_len 仅支持 128，其他值直接报错
                TORCH_CHECK(block_len == 128,
                            "blockwise_scaled_cast_transpose: only block_len=128 is supported, got ",
                            block_len);
                if (128 == block_len) {

                    if (rowwise_option != FP8BlockwiseRowwiseOption::NONE)
                    {
                      size_t smem_bytes = kFP32SMemSize * sizeof(InputType);
                      if (smem_bytes >= 48 * 1024) {
                        hipError_t err = hipFuncSetAttribute(
                            (const void*)&block_scaled_1d_cast_transpose_kernel_rowwise<
                                kAligned, float, InputType, OutputType>,
                            hipFuncAttributeMaxDynamicSharedMemorySize, smem_bytes);
                        // 设置共享内存上限后检查返回值，失败直接报错
                        TORCH_CHECK(err == hipSuccess,
                                    "hipFuncSetAttribute(rowwise, ", smem_bytes, "B) failed: ",
                                    hipGetErrorString(err));
                      }

                      block_scaled_1d_cast_transpose_kernel_rowwise<kAligned, float, InputType,
                                                                OutputType>
                          <<<grid, kThreadsPerBlock, smem_bytes, at::hip::getCurrentHIPStream()>>>(
                              reinterpret_cast<const InputType*>(input.data_ptr()),
                              reinterpret_cast<OutputType*>(output.value().data_ptr()),
                              reinterpret_cast<float*>(scale_inv.value().data_ptr()),
                              row_length, num_rows,scale_stride_x, scale_stride_y,
                              epsilon, rowwise_option, pow2_scale);
                    }
                    if (columnwise_option != FP8BlockwiseColumnwiseOption::NONE)
                    {

                        size_t smem_bytes = kSMemSize_Colwise * sizeof(InputType);
                        const size_t num_blocks_x = DIVUP(row_length, (size_t)(block_len/2));//1024/64=16
                        const size_t num_blocks_y = DIVUP(num_rows, (size_t)(block_len));//2
                        dim3 grid(num_blocks_x, num_blocks_y, 1);
                        // 与 rowwise 分支同规则：smem < 48KB 不调用；
                        // 超限时检查返回值，失败直接报错
                        if (smem_bytes >= 48 * 1024) {
                          hipError_t err = hipFuncSetAttribute(
                              (const void*)&block_scaled_1d_cast_transpose_kernel_colwise<
                                  kAligned, float, InputType, OutputType>,
                              hipFuncAttributeMaxDynamicSharedMemorySize, smem_bytes);
                          TORCH_CHECK(err == hipSuccess,
                                      "hipFuncSetAttribute(colwise, ", smem_bytes, "B) failed: ",
                                      hipGetErrorString(err));
                        }
                        block_scaled_1d_cast_transpose_kernel_colwise<kAligned, float, InputType,
                                                                OutputType>
                          <<<grid, kThreadsPerBlock_Colwise, smem_bytes, at::hip::getCurrentHIPStream()>>>(
                             reinterpret_cast<const InputType*>(input.data_ptr()),
                              reinterpret_cast<OutputType*>(output_transpose.value().data_ptr()),
                              reinterpret_cast<float*>(scale_inv_transpose.value().data_ptr()),
                              row_length, num_rows,
                              scale_t_stride_x, scale_t_stride_y,
                              epsilon, columnwise_option, pow2_scale);
                    }

                }

              }

              )  // kAligned
          )      // OutputType
      )          // InputType
  TORCH_CHECK_CUDA(hipGetLastError());
}


void blockwise_scaled_cast_transpose(const at::Tensor& input,std::optional<at::Tensor> output,std::optional<at::Tensor> scale_inv,
                                    std::optional<at::Tensor> output_transpose,std::optional<at::Tensor> scale_inv_transpose,
                                    const int block_len,const int block_scaling_dim,const bool rowwise,const bool columnwise,
                                    const float epsilon,const bool pow2_scale,const bool all_gather_usage, at::ScalarType out_dtype)
    {

      if(block_scaling_dim==1)
      {

          blockwise_scaled_1d_cast_transpose(input,output,scale_inv,output_transpose,scale_inv_transpose,block_len,rowwise,
                                             columnwise,epsilon,pow2_scale,all_gather_usage,out_dtype);
      }

      else if (block_scaling_dim==2)
      {
          TORCH_ERROR("BLOCK_SCALING_2D is not support.");

      }


    }

}  // namespace blockwise
}  // namespace aiter
