// SPDX-License-Identifier: MIT

#include <ATen/Dispatch.h>
#include <ATen/hip/HIPContext.h>
#include <c10/hip/HIPException.h>
#include <hip/hip_runtime.h>
#include <torch/extension.h>

#include <cmath>
#include <cstddef>
#include <cstdint>
#include <limits>
#include <vector>

#include "arch.h"
#include "fla.h"

#ifndef AITER_HIP_KERNEL_LAUNCH_CHECK
#if defined(C10_CUDA_KERNEL_LAUNCH_CHECK)
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_CUDA_KERNEL_LAUNCH_CHECK()
#elif defined(C10_HIP_KERNEL_LAUNCH_CHECK)
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_HIP_KERNEL_LAUNCH_CHECK()
#else
#define AITER_HIP_KERNEL_LAUNCH_CHECK() C10_HIP_CHECK(hipGetLastError())
#endif
#endif

#define FLA_ERR "aiter_fused_recurrent_gated_delta_rule_packed_decode: "

namespace {

constexpr int kWaveSize = 64;
constexpr int kMaxThreads = 256;
constexpr int kBlocksPerCU = 8;
constexpr int kMaxRows = 8;
constexpr int kStaticK = 128;
constexpr int kStaticV = 128;
constexpr float kSoftplusThreshold = 20.0f;
constexpr float kLog2e = 1.44269504088896340736f;

using fla_b128 = __attribute__((__vector_size__(16))) unsigned int;

template <typename scalar_t>
__device__ __forceinline__ float to_float(scalar_t x)
{
    return static_cast<float>(x);
}

template <typename scalar_t, int N>
struct alignas(sizeof(scalar_t) * N) ScalarPack
{
    scalar_t value[N];
};

__device__ __forceinline__ float fast_expf(float x)
{
    return __builtin_amdgcn_exp2f(x * kLog2e);
}

__device__ __forceinline__ float sigmoidf_plain(float x)
{
    return __builtin_amdgcn_rcpf(1.0f + __builtin_amdgcn_exp2f(-x * kLog2e));
}

__device__ __forceinline__ float softplus_threshold(float x)
{
    return x <= kSoftplusThreshold ? log1pf(fast_expf(x)) : x;
}

enum FlaScalarKind : int { kF32 = 0, kF16 = 1, kBF16 = 2 };

struct FlaGateArgs
{
    const void* a;
    const void* b;
    const void* A_log;
    const void* dt_bias;
    int64_t stride_a_tok;
    int64_t stride_b_tok;
    int a_kind;
    int b_kind;
    int A_log_kind;
    int dt_bias_kind;
};

__device__ __forceinline__ float fla_load_scalar(const void* __restrict__ p,
                                                 int64_t i, int kind)
{
    if (kind == kF32) return reinterpret_cast<const float*>(p)[i];
    if (kind == kF16) return static_cast<float>(reinterpret_cast<const c10::Half*>(p)[i]);
    return static_cast<float>(reinterpret_cast<const c10::BFloat16*>(p)[i]);
}

template <int GroupSize>
__device__ __forceinline__ float group_sum_n(float v)
{
#pragma unroll
    for (int m = GroupSize / 2; m > 0; m >>= 1) v += __shfl_xor(v, m, GroupSize);
    return v;
}

template <typename T, int N>
__device__ __forceinline__ void zero_pack(ScalarPack<T, N>& d)
{
#pragma unroll
    for (int j = 0; j < N; ++j) d.value[j] = static_cast<T>(0.0f);
}

template <typename T, int N>
__device__ __forceinline__ void state_load_pack(const T* src, ScalarPack<T, N>& d)
{
    static_assert(N * sizeof(T) == 16, "state pack must be 16 bytes");
    *reinterpret_cast<fla_b128*>(&d) =
        __builtin_nontemporal_load(reinterpret_cast<const fla_b128*>(src));
}

template <typename T, int N>
__device__ __forceinline__ void state_store_pack(T* dst, const ScalarPack<T, N>& s)
{
    static_assert(N * sizeof(T) == 16, "state pack must be 16 bytes");
    __builtin_nontemporal_store(*reinterpret_cast<const fla_b128*>(&s),
                                reinterpret_cast<fla_b128*>(dst));
}

template <typename input_t, typename state_t, typename index_t,
          int GroupSize, int Packs, int Rows, int BlockThreads,
          int KConst, int VConst, bool UseQkL2Norm>
__global__ __launch_bounds__(BlockThreads)
void fused_recurrent_gated_delta_rule_packed_decode_base_kernel(
    const input_t* __restrict__ mixed_qkv,
    FlaGateArgs gates,
    input_t* __restrict__ out,
    state_t* __restrict__ state,
    const index_t* __restrict__ ssm_state_indices,
    float scale,
    int64_t stride_mixed_qkv_tok,
    int64_t stride_state_slot,
    int64_t stride_state_hv,
    int64_t stride_state_v,
    int64_t stride_state_k,
    int64_t stride_indices_seq,
    int H, int HV, int K_arg, int V_arg)
{
    constexpr bool kGeneric = (Packs == 0);
    constexpr int kVecW = 16 / static_cast<int>(sizeof(state_t));
    constexpr int kElems = kGeneric ? 1 : Packs * kVecW;
    constexpr int kRows = kGeneric ? 1 : Rows;
    constexpr int kWaveGroups = kWaveSize / GroupSize;
    constexpr int kRowsPerWave = kRows * kWaveGroups;
    constexpr int kRowsPerBlock = (BlockThreads / kWaveSize) * kRowsPerWave;
    constexpr int kSpan = GroupSize * kVecW;

    static_assert(GroupSize >= 4 && GroupSize <= kWaveSize, "group inside a wave");
    static_assert((GroupSize & (GroupSize - 1)) == 0, "group must be pow2");
    static_assert(BlockThreads % kWaveSize == 0, "block must be wave aligned");
    static_assert(kVecW * static_cast<int>(sizeof(state_t)) == 16, "16 B vector");

    const int K = (KConst > 0) ? KConst : K_arg;
    const int V = (VConst > 0) ? VConst : V_arg;
    const int64_t row_stride = kGeneric ? stride_state_v : static_cast<int64_t>(K);
    const int64_t hv_stride =
        kGeneric ? stride_state_hv : static_cast<int64_t>(V) * K;

    const int tid = threadIdx.x;
    const int wave = tid / kWaveSize;
    const int lane = tid & (kWaveSize - 1);
    const int gidx = lane / GroupSize;
    const int glane = lane & (GroupSize - 1);
    const int row0 = static_cast<int>(blockIdx.x) * kRowsPerBlock +
        wave * kRowsPerWave + gidx * kRows;

    const int hv = blockIdx.y;
    const int n = blockIdx.z;

    const int64_t state_idx = static_cast<int64_t>(
        ssm_state_indices[static_cast<int64_t>(n) * stride_indices_seq]);
    const int64_t out_hv_base = (static_cast<int64_t>(n) * HV + hv) * V;

    if (state_idx < 0) {
        if (glane == 0) {
#pragma unroll
            for (int r = 0; r < kRows; ++r)
                if (row0 + r < V) out[out_hv_base + row0 + r] = static_cast<input_t>(0.0f);
        }
        return;
    }
    if (row0 >= V) return;

    state_t* const state_hv_base =
        state + state_idx * stride_state_slot + static_cast<int64_t>(hv) * hv_stride;
    const int64_t mixed_base = static_cast<int64_t>(n) * stride_mixed_qkv_tok;
    const int qk_head = hv / (HV / H);
    const input_t* const q_ptr =
        mixed_qkv + mixed_base + static_cast<int64_t>(qk_head) * K;
    const input_t* const k_ptr =
        mixed_qkv + mixed_base + static_cast<int64_t>(H + qk_head) * K;
    const int64_t v_hv_base = mixed_base +
        static_cast<int64_t>(2) * H * K + static_cast<int64_t>(hv) * V;

    if constexpr (!kGeneric) {
        const bool full_tile = (row0 + kRows <= V);

        bool pack_ok[Packs];
#pragma unroll
        for (int p = 0; p < Packs; ++p) pack_ok[p] = (p * kSpan + glane * kVecW) < K;

        ScalarPack<state_t, kVecW> h_raw[kRows * Packs];
#pragma unroll
        for (int r = 0; r < kRows; ++r) {
            const int row = row0 + r;
            const state_t* const rp = state_hv_base +
                static_cast<int64_t>(row < V ? row : V - 1) * row_stride;
#pragma unroll
            for (int p = 0; p < Packs; ++p) {
                if (pack_ok[p]) state_load_pack(rp + p * kSpan + glane * kVecW, h_raw[r * Packs + p]);
                else zero_pack(h_raw[r * Packs + p]);
            }
        }

        float v_reg[kRows];
        if (full_tile) {
            const ScalarPack<input_t, kRows> vp =
                *reinterpret_cast<const ScalarPack<input_t, kRows>*>(
                    mixed_qkv + v_hv_base + row0);
#pragma unroll
            for (int r = 0; r < kRows; ++r) v_reg[r] = to_float(vp.value[r]);
        } else {
#pragma unroll
            for (int r = 0; r < kRows; ++r)
                v_reg[r] = (row0 + r < V) ? to_float(mixed_qkv[v_hv_base + row0 + r]) : 0.0f;
        }

        float q_v[kElems], k_v[kElems], q_sq = 0.0f, k_sq = 0.0f;
#pragma unroll
        for (int p = 0; p < Packs; ++p) {
            const int kk = p * kSpan + glane * kVecW;
            ScalarPack<input_t, kVecW> qp, kp;
            if (pack_ok[p]) {
                qp = *reinterpret_cast<const ScalarPack<input_t, kVecW>*>(q_ptr + kk);
                kp = *reinterpret_cast<const ScalarPack<input_t, kVecW>*>(k_ptr + kk);
            } else {
                zero_pack(qp);
                zero_pack(kp);
            }
#pragma unroll
            for (int j = 0; j < kVecW; ++j) {
                const int i = p * kVecW + j;
                q_v[i] = to_float(qp.value[j]);
                k_v[i] = to_float(kp.value[j]);
                if constexpr (UseQkL2Norm) {
                    q_sq = fmaf(q_v[i], q_v[i], q_sq);
                    k_sq = fmaf(k_v[i], k_v[i], k_sq);
                }
            }
        }

        float q_mul = scale, k_mul = 1.0f;
        if constexpr (UseQkL2Norm) {
            q_mul = rsqrtf(group_sum_n<GroupSize>(q_sq) + 1.0e-6f) * scale;
            k_mul = rsqrtf(group_sum_n<GroupSize>(k_sq) + 1.0e-6f);
        }
#pragma unroll
        for (int i = 0; i < kElems; ++i) {
            q_v[i] *= q_mul;
            if constexpr (UseQkL2Norm) k_v[i] *= k_mul;
        }

        const float gate_x =
            fla_load_scalar(gates.a, static_cast<int64_t>(n) * gates.stride_a_tok + hv, gates.a_kind) +
            fla_load_scalar(gates.dt_bias, hv, gates.dt_bias_kind);
        const float gate = fast_expf(
            -fast_expf(fla_load_scalar(gates.A_log, hv, gates.A_log_kind)) *
            softplus_threshold(gate_x));
        const float beta = sigmoidf_plain(fla_load_scalar(
            gates.b, static_cast<int64_t>(n) * gates.stride_b_tok + hv, gates.b_kind));

        float qk_dot = 0.0f;
#pragma unroll
        for (int i = 0; i < kElems; ++i) qk_dot = fmaf(k_v[i], q_v[i], qk_dot);
        qk_dot = group_sum_n<GroupSize>(qk_dot);

        float out_val[kRows];
#pragma unroll
        for (int r = 0; r < kRows; ++r) {
            float h_frag[kElems], hk_part = 0.0f, hq_part = 0.0f;
#pragma unroll
            for (int p = 0; p < Packs; ++p) {
#pragma unroll
                for (int j = 0; j < kVecW; ++j) {
                    const int i = p * kVecW + j;
                    h_frag[i] = to_float(h_raw[r * Packs + p].value[j]) * gate;
                    hk_part = fmaf(h_frag[i], k_v[i], hk_part);
                    hq_part = fmaf(h_frag[i], q_v[i], hq_part);
                }
            }
            const float hk = group_sum_n<GroupSize>(hk_part);
            const float hq = group_sum_n<GroupSize>(hq_part);
            const float v_delta = (v_reg[r] - hk) * beta;

            const int row = row0 + r;
            const bool row_ok = full_tile || (row < V);
            state_t* const rp = state_hv_base + static_cast<int64_t>(row) * row_stride;
#pragma unroll
            for (int p = 0; p < Packs; ++p) {
                ScalarPack<state_t, kVecW> op;
#pragma unroll
                for (int j = 0; j < kVecW; ++j) {
                    const int i = p * kVecW + j;
                    op.value[j] = static_cast<state_t>(fmaf(v_delta, k_v[i], h_frag[i]));
                }
                if (row_ok && pack_ok[p])
                    state_store_pack(rp + p * kSpan + glane * kVecW, op);
            }
            out_val[r] = fmaf(v_delta, qk_dot, hq);
        }

        if (glane == 0) {
            if (full_tile) {
                ScalarPack<input_t, kRows> op;
#pragma unroll
                for (int r = 0; r < kRows; ++r) op.value[r] = static_cast<input_t>(out_val[r]);
                *reinterpret_cast<ScalarPack<input_t, kRows>*>(out + out_hv_base + row0) = op;
            } else {
#pragma unroll
                for (int r = 0; r < kRows; ++r)
                    if (row0 + r < V)
                        out[out_hv_base + row0 + r] = static_cast<input_t>(out_val[r]);
            }
        }
    } else {
        const int row = row0;
        state_t* const sp = state_hv_base + static_cast<int64_t>(row) * row_stride;

        float q_mul = scale, k_mul = 1.0f;
        if constexpr (UseQkL2Norm) {
            float q_sq = 0.0f, k_sq = 0.0f;
            for (int kk = glane; kk < K; kk += GroupSize) {
                const float qv = to_float(q_ptr[kk]), kv = to_float(k_ptr[kk]);
                q_sq = fmaf(qv, qv, q_sq);
                k_sq = fmaf(kv, kv, k_sq);
            }
            q_mul = rsqrtf(group_sum_n<GroupSize>(q_sq) + 1.0e-6f) * scale;
            k_mul = rsqrtf(group_sum_n<GroupSize>(k_sq) + 1.0e-6f);
        }

        const float gate_x =
            fla_load_scalar(gates.a, static_cast<int64_t>(n) * gates.stride_a_tok + hv, gates.a_kind) +
            fla_load_scalar(gates.dt_bias, hv, gates.dt_bias_kind);
        const float gate = fast_expf(
            -fast_expf(fla_load_scalar(gates.A_log, hv, gates.A_log_kind)) *
            softplus_threshold(gate_x));
        const float beta = sigmoidf_plain(fla_load_scalar(
            gates.b, static_cast<int64_t>(n) * gates.stride_b_tok + hv, gates.b_kind));

        float hk_part = 0.0f, hq_part = 0.0f, qk_part = 0.0f;
        for (int kk = glane; kk < K; kk += GroupSize) {
            const float h = to_float(sp[static_cast<int64_t>(kk) * stride_state_k]) * gate;
            const float kv = to_float(k_ptr[kk]) * k_mul;
            const float qv = to_float(q_ptr[kk]) * q_mul;
            hk_part = fmaf(h, kv, hk_part);
            hq_part = fmaf(h, qv, hq_part);
            qk_part = fmaf(kv, qv, qk_part);
        }
        const float hk = group_sum_n<GroupSize>(hk_part);
        const float hq = group_sum_n<GroupSize>(hq_part);
        const float qk_dot = group_sum_n<GroupSize>(qk_part);
        const float v_delta = (to_float(mixed_qkv[v_hv_base + row]) - hk) * beta;

        for (int kk = glane; kk < K; kk += GroupSize) {
            const int64_t off = static_cast<int64_t>(kk) * stride_state_k;
            sp[off] = static_cast<state_t>(
                fmaf(v_delta, to_float(k_ptr[kk]) * k_mul, to_float(sp[off]) * gate));
        }
        if (glane == 0)
            out[out_hv_base + row] = static_cast<input_t>(fmaf(v_delta, qk_dot, hq));
    }
}

struct LaunchArgs
{
    const void* mixed;
    void* out;
    void* state;
    const void* indices;
    FlaGateArgs gates;
    float scale;
    int64_t s_qkv, s_slot, s_hv, s_v, s_k, s_idx;
    int B, H, HV, K, V;
};

int fla_scalar_kind(at::ScalarType t)
{
    switch (t) {
        case at::ScalarType::Float: return kF32;
        case at::ScalarType::Half: return kF16;
        case at::ScalarType::BFloat16: return kBF16;
        default: TORCH_CHECK(false, FLA_ERR "gating tensors must be fp32/fp16/bf16");
    }
    return kF32;
}

torch::Tensor ensure_gate_layout(const torch::Tensor& t)
{
    const int64_t last = t.dim() - 1;
    return (last >= 0 && t.stride(last) == 1) ? t : t.contiguous();
}

int cu_count()
{
    static int cached = 0;
    if (cached == 0) {
        int dev = 0;
        hipDeviceProp_t prop{};
        cached = (hipGetDevice(&dev) == hipSuccess &&
                  hipGetDeviceProperties(&prop, dev) == hipSuccess &&
                  prop.multiProcessorCount > 0)
            ? prop.multiProcessorCount
            : 64;
    }
    return cached;
}

int pick_block_threads(int rows_per_wave, int B, int HV, int V)
{
    const int64_t target = static_cast<int64_t>(cu_count()) * kBlocksPerCU;
    int threads = kMaxThreads;
    while (threads > kWaveSize) {
        const int rows = (threads / kWaveSize) * rows_per_wave;
        if (rows <= V) {
            const int64_t blocks =
                static_cast<int64_t>(HV) * B * ((V + rows - 1) / rows);
            if (blocks >= target) break;
        }
        threads >>= 1;
    }
    return threads;
}

template <typename input_t, typename state_t, typename index_t,
          int GroupSize, int Packs, int Rows, int BlockThreads,
          int KConst, int VConst, bool UseQkL2Norm>
void launch_tier(const LaunchArgs& A, hipStream_t stream)
{
    constexpr int kRows = (Packs == 0) ? 1 : Rows;
    constexpr int kRowsPerBlock =
        (BlockThreads / kWaveSize) * kRows * (kWaveSize / GroupSize);

    const dim3 grid(static_cast<unsigned int>((A.V + kRowsPerBlock - 1) / kRowsPerBlock),
                    static_cast<unsigned int>(A.HV),
                    static_cast<unsigned int>(A.B));

    hipLaunchKernelGGL(
        HIP_KERNEL_NAME(fused_recurrent_gated_delta_rule_packed_decode_base_kernel<
            input_t, state_t, index_t, GroupSize, Packs, Rows, BlockThreads,
            KConst, VConst, UseQkL2Norm>),
        grid, dim3(BlockThreads), 0, stream,
        reinterpret_cast<const input_t*>(A.mixed),
        A.gates,
        reinterpret_cast<input_t*>(A.out),
        reinterpret_cast<state_t*>(A.state),
        reinterpret_cast<const index_t*>(A.indices),
        A.scale, A.s_qkv, A.s_slot, A.s_hv, A.s_v, A.s_k, A.s_idx,
        A.H, A.HV, A.K, A.V);
}

template <typename input_t, typename state_t, typename index_t,
          int GroupSize, int Packs, int Rows, bool UseQkL2Norm>
void launch_config(const LaunchArgs& A, hipStream_t stream)
{
    constexpr int kRowsPerWave = Rows * (kWaveSize / GroupSize);
    const int threads = pick_block_threads(kRowsPerWave, A.B, A.HV, A.V);

    if (threads == kMaxThreads && A.K == kStaticK && A.V == kStaticV) {
        launch_tier<input_t, state_t, index_t, GroupSize, Packs, Rows, kMaxThreads,
                    kStaticK, kStaticV, UseQkL2Norm>(A, stream);
        return;
    }
    switch (threads) {
        case 256:
            launch_tier<input_t, state_t, index_t, GroupSize, Packs, Rows, 256, 0, 0, UseQkL2Norm>(A, stream);
            break;
        case 128:
            launch_tier<input_t, state_t, index_t, GroupSize, Packs, Rows, 128, 0, 0, UseQkL2Norm>(A, stream);
            break;
        default:
            launch_tier<input_t, state_t, index_t, GroupSize, Packs, Rows, 64, 0, 0, UseQkL2Norm>(A, stream);
            break;
    }
}

template <typename input_t, typename state_t>
bool vector_path_ok(const LaunchArgs& A)
{
    constexpr int kVecW = 16 / static_cast<int>(sizeof(state_t));
    if (A.K <= 0 || A.K % kVecW || A.K / kVecW > kWaveSize * 4) return false;
    if (A.K % kMaxRows || A.V % kMaxRows) return false;
    if (A.s_slot % kVecW || A.s_qkv % kVecW || A.s_qkv % kMaxRows) return false;
    if (A.s_hv != static_cast<int64_t>(A.V) * A.K || A.s_v != A.K || A.s_k != 1) return false;
    constexpr std::size_t kRowBytes = kMaxRows * sizeof(input_t);
    if (reinterpret_cast<uintptr_t>(A.state) % 16) return false;
    if (reinterpret_cast<uintptr_t>(A.out) % kRowBytes) return false;
    const uintptr_t m = reinterpret_cast<uintptr_t>(A.mixed);
    return (m % (kVecW * sizeof(input_t))) == 0 && (m % kRowBytes) == 0;
}

#define FLA_BD_TRY(GROUP, PACKS, ROWS)                                        \
    if (vectors <= (GROUP) * (PACKS)) {                                       \
        launch_config<input_t, state_t, index_t, (GROUP), (PACKS), (ROWS), L>( \
            A, s);                                                            \
        return;                                                               \
    }

template <typename input_t, typename state_t, typename index_t, bool L>
void launch_by_shape(const LaunchArgs& A, hipStream_t s)
{
    constexpr int kVecW = 16 / static_cast<int>(sizeof(state_t));
    if (vector_path_ok<input_t, state_t>(A)) {
        const int vectors = A.K / kVecW;
        FLA_BD_TRY(8, 1, 8)
        FLA_BD_TRY(8, 2, 4)
        FLA_BD_TRY(16, 2, 4)
        FLA_BD_TRY(16, 4, 2)
        FLA_BD_TRY(32, 4, 2)
        FLA_BD_TRY(64, 4, 2)
    }
    launch_tier<input_t, state_t, index_t, kWaveSize, 0, 1, kMaxThreads, 0, 0, L>(A, s);
}

#undef FLA_BD_TRY

#define FLA_BD_DISPATCH_FLOAT(TYPE, NAME, ...)                                \
    AT_DISPATCH_SWITCH(TYPE, NAME,                                            \
        AT_DISPATCH_CASE(at::ScalarType::Float, __VA_ARGS__)                  \
        AT_DISPATCH_CASE(at::ScalarType::Half, __VA_ARGS__)                   \
        AT_DISPATCH_CASE(at::ScalarType::BFloat16, __VA_ARGS__))

bool is_supported_float_dtype(at::ScalarType d)
{
    return d == at::ScalarType::Float || d == at::ScalarType::Half ||
        d == at::ScalarType::BFloat16;
}

void check_tensor(const torch::Tensor& t, const char* name, bool need_float)
{
    TORCH_CHECK(t.is_cuda(), FLA_ERR, name, " must be a CUDA/HIP tensor");
    TORCH_CHECK(!need_float || is_supported_float_dtype(t.scalar_type()),
                FLA_ERR, name, " must be fp32, fp16, or bf16");
}

}  // namespace

std::vector<at::Tensor>
aiter_fused_recurrent_gated_delta_rule_packed_decode(
    at::Tensor const& mixed_qkv,
    at::Tensor const& a,
    at::Tensor const& b,
    at::Tensor const& A_log,
    at::Tensor const& dt_bias,
    float scale,
    at::Tensor const& initial_state,
    at::Tensor const& out,
    at::Tensor const& ssm_state_indices,
    bool use_qk_l2norm_in_kernel)
{
    check_tensor(mixed_qkv, "mixed_qkv", true);
    check_tensor(a, "a", true);
    check_tensor(b, "b", true);
    check_tensor(A_log, "A_log", true);
    check_tensor(dt_bias, "dt_bias", true);
    check_tensor(initial_state, "initial_state", true);
    check_tensor(out, "out", true);
    check_tensor(ssm_state_indices, "ssm_state_indices", false);

    const auto dev = mixed_qkv.device();
    TORCH_CHECK(a.device() == dev && b.device() == dev && A_log.device() == dev &&
                    dt_bias.device() == dev && initial_state.device() == dev &&
                    out.device() == dev && ssm_state_indices.device() == dev,
                FLA_ERR "all tensors must be on the same device");
    TORCH_CHECK(out.scalar_type() == mixed_qkv.scalar_type(),
                FLA_ERR "out dtype must match mixed_qkv");
    TORCH_CHECK(ssm_state_indices.scalar_type() == at::ScalarType::Int ||
                    ssm_state_indices.scalar_type() == at::ScalarType::Long,
                FLA_ERR "ssm_state_indices must be int32 or int64");
    TORCH_CHECK(mixed_qkv.dim() == 2 && a.dim() == 2 && b.dim() == 2 &&
                    A_log.dim() == 1 && dt_bias.dim() == 1 &&
                    initial_state.dim() == 4 && out.dim() == 4 &&
                    ssm_state_indices.dim() == 1,
                FLA_ERR "unexpected tensor ranks");

    const int64_t B64 = mixed_qkv.size(0);
    const int64_t HV64 = initial_state.size(1);
    const int64_t V64 = initial_state.size(2);
    const int64_t K64 = initial_state.size(3);
    TORCH_CHECK(K64 > 0 && V64 > 0, FLA_ERR "K and V must be positive");
    TORCH_CHECK(a.size(0) == B64 && b.size(0) == B64 &&
                    ssm_state_indices.size(0) == B64,
                FLA_ERR "batch dimensions must match");
    TORCH_CHECK(a.size(1) == HV64 && b.size(1) == HV64 &&
                    A_log.numel() == HV64 && dt_bias.numel() == HV64,
                FLA_ERR "gating tensors must match HV");
    TORCH_CHECK(out.size(0) == B64 && out.size(1) == 1 && out.size(2) == HV64 &&
                    out.size(3) == V64,
                FLA_ERR "out must have shape [B, 1, HV, V]");

    const int64_t qk_dim = mixed_qkv.size(1) - HV64 * V64;
    TORCH_CHECK(qk_dim > 0 && qk_dim % 2 == 0, FLA_ERR "invalid mixed_qkv layout");
    TORCH_CHECK((qk_dim / 2) % K64 == 0, FLA_ERR "q dim must be divisible by K");
    const int64_t H64 = (qk_dim / 2) / K64;
    TORCH_CHECK(H64 > 0 && HV64 >= H64 && HV64 % H64 == 0, FLA_ERR "invalid H/HV");
    TORCH_CHECK(B64 <= std::numeric_limits<int>::max() &&
                    HV64 <= std::numeric_limits<int>::max() &&
                    K64 <= std::numeric_limits<int>::max() &&
                    V64 <= std::numeric_limits<int>::max(),
                FLA_ERR "tensor dimensions are too large");
    TORCH_CHECK(out.is_contiguous(), FLA_ERR "out must be contiguous");
    TORCH_CHECK(initial_state.stride(1) == V64 * K64 &&
                    initial_state.stride(2) == K64 &&
                    initial_state.stride(3) == 1,
                FLA_ERR "initial_state trailing dimensions must be contiguous");

    if (out.numel() == 0) return {out, initial_state};

    const auto mixed = mixed_qkv.contiguous();
    const auto idx = ssm_state_indices.contiguous();
    const auto av = ensure_gate_layout(a);
    const auto bv = ensure_gate_layout(b);
    const auto alv = ensure_gate_layout(A_log);
    const auto dbv = ensure_gate_layout(dt_bias);

    LaunchArgs args{};
    args.mixed = mixed.data_ptr();
    args.out = out.data_ptr();
    args.state = initial_state.data_ptr();
    args.indices = idx.data_ptr();
    args.gates = FlaGateArgs{av.data_ptr(), bv.data_ptr(), alv.data_ptr(),
                             dbv.data_ptr(), av.stride(0), bv.stride(0),
                             fla_scalar_kind(av.scalar_type()),
                             fla_scalar_kind(bv.scalar_type()),
                             fla_scalar_kind(alv.scalar_type()),
                             fla_scalar_kind(dbv.scalar_type())};
    args.scale = scale;
    args.s_qkv = mixed.stride(0);
    args.s_slot = initial_state.stride(0);
    args.s_hv = initial_state.stride(1);
    args.s_v = initial_state.stride(2);
    args.s_k = initial_state.stride(3);
    args.s_idx = idx.stride(0);
    args.B = static_cast<int>(B64);
    args.H = static_cast<int>(H64);
    args.HV = static_cast<int>(HV64);
    args.K = static_cast<int>(K64);
    args.V = static_cast<int>(V64);

    const bool i32 = idx.scalar_type() == at::ScalarType::Int;
    auto stream = at::hip::getCurrentHIPStream().stream();

    FLA_BD_DISPATCH_FLOAT(mixed.scalar_type(), "fla_packed_decode_in", [&] {
        using input_t = scalar_t;
        FLA_BD_DISPATCH_FLOAT(initial_state.scalar_type(), "fla_packed_decode_state", [&] {
            using state_t = scalar_t;
            if (use_qk_l2norm_in_kernel) {
                if (i32) launch_by_shape<input_t, state_t, int32_t, true>(args, stream);
                else launch_by_shape<input_t, state_t, int64_t, true>(args, stream);
            } else {
                if (i32) launch_by_shape<input_t, state_t, int32_t, false>(args, stream);
                else launch_by_shape<input_t, state_t, int64_t, false>(args, stream);
            }
        });
    });

    AITER_HIP_KERNEL_LAUNCH_CHECK();
    return {out, initial_state};
}
