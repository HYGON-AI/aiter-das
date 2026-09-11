// SPDX-License-Identifier: MIT

#include <ATen/Dispatch.h>
#include <ATen/hip/HIPContext.h>
#include <c10/hip/HIPException.h>
#include <hip/hip_runtime.h>
#include <torch/extension.h>

#include <cmath>
#include <cstdint>
#include <cstdlib>
#include <optional>
#include <vector>

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

#ifndef AITER_FSG_NONTEMPORAL
#define AITER_FSG_NONTEMPORAL 1
#endif

#ifndef AITER_FSG_BLOCK_THREADS
#define AITER_FSG_BLOCK_THREADS 256
#endif

#ifndef AITER_FSG_VROWS
#define AITER_FSG_VROWS 1
#endif

namespace {

typedef float f32x4 __attribute__((ext_vector_type(4)));

constexpr int kVec = 4;
constexpr int kBlockThreads = AITER_FSG_BLOCK_THREADS;
constexpr int kVRows = AITER_FSG_VROWS;

template <typename T>
struct alignas(sizeof(T) * kVec) Vec4 {
    T v[kVec];
};

template <typename scalar_t>
struct FsgParams {
    const float* __restrict__ A_log;
    const scalar_t* __restrict__ a;
    const scalar_t* __restrict__ b;
    const scalar_t* __restrict__ dt_bias;
    const scalar_t* __restrict__ q;
    const scalar_t* __restrict__ k;
    const scalar_t* __restrict__ v;
    scalar_t* __restrict__ o;
    const float* __restrict__ state_in;
    float* __restrict__ state_out;
    const int32_t* __restrict__ cu_seqlens;
    const int32_t* __restrict__ idx_read;
    const int32_t* __restrict__ idx_write;
    const int32_t* __restrict__ num_accepted;
    int64_t si_slot;
    int64_t si_hv;
    int64_t si_v;
    int64_t so_slot;
    int64_t so_hv;
    int64_t so_v;
    float beta;
    float inv_beta;
    float threshold;
    float scale;
    int T_total;
    int H;
    int HV;
    int V;
    int h_ratio;
    int idx_stride;
};

__device__ __forceinline__ f32x4 ld_state(const f32x4* p)
{
#if AITER_FSG_NONTEMPORAL
    return __builtin_nontemporal_load(p);
#else
    return *p;
#endif
}

__device__ __forceinline__ void st_state(f32x4* p, f32x4 x)
{
#if AITER_FSG_NONTEMPORAL
    __builtin_nontemporal_store(x, p);
#else
    *p = x;
#endif
}

__device__ __forceinline__ float softplus_th(float x, float beta, float inv_beta, float th)
{
    const float bx = beta * x;
    return bx <= th ? __logf(1.0f + __expf(bx)) * inv_beta : x;
}

template <typename scalar_t,
          int NumChunk,
          int GroupSize,
          int BlockThreads,
          int VRows,
          bool UseNorm,
          bool IsKda>
__global__ __launch_bounds__(BlockThreads)
void vllm_fused_sigmoid_gating_delta_rule_update_kernel(FsgParams<scalar_t> p)
{
    constexpr int K = NumChunk * GroupSize * kVec;
    constexpr int VecK = NumChunk * GroupSize;
    constexpr int Groups = BlockThreads / GroupSize;
    constexpr int RowsPerBlock = Groups * VRows;
    static_assert(BlockThreads % GroupSize == 0, "");
    static_assert(GroupSize >= 4 && GroupSize <= 64, "");

    const int tid = static_cast<int>(threadIdx.x);
    const int lane = tid & (GroupSize - 1);
    const int gid = tid / GroupSize;
    const int v0 = static_cast<int>(blockIdx.z) * RowsPerBlock + gid * VRows;
    if (v0 >= p.V) {
        return;
    }

    const int n = static_cast<int>(blockIdx.x);
    const int hv = static_cast<int>(blockIdx.y);

    int bos;
    int T_cur;
    if (p.cu_seqlens != nullptr) {
        bos = p.cu_seqlens[n];
        T_cur = p.cu_seqlens[n + 1] - bos;
    } else {
        bos = n * p.T_total;
        T_cur = p.T_total;
    }
    if (T_cur <= 0) {
        return;
    }

    int init_t = 0;
    if (p.num_accepted != nullptr) {
        init_t = p.num_accepted[n] - 1;
        if (init_t < 0) {
            return;
        }
    }

    int64_t slot_in = bos;
    if (p.idx_read != nullptr) {
        const int s = p.idx_read[static_cast<int64_t>(n) * p.idx_stride + init_t];
        if (s < 0) {
            return;
        }
        slot_in = s;
    }

    bool row_ok[VRows];
#pragma unroll
    for (int r = 0; r < VRows; ++r) {
        row_ok[r] = (VRows == 1) ? true : (v0 + r) < p.V;
    }

    const int h = hv / p.h_ratio;

    f32x4 hs[VRows][NumChunk];
    {
        const float* sb = p.state_in + slot_in * p.si_slot +
                          static_cast<int64_t>(hv) * p.si_hv;
#pragma unroll
        for (int r = 0; r < VRows; ++r) {
            const f32x4* sp = reinterpret_cast<const f32x4*>(
                sb + static_cast<int64_t>(v0 + r) * p.si_v);
#pragma unroll
            for (int j = 0; j < NumChunk; ++j) {
                hs[r][j] = row_ok[r] ? ld_state(sp + (j * GroupSize + lane)) : f32x4(0.0f);
            }
        }
    }

    const float A = __expf(p.A_log[hv]);

    float dts = 0.0f;
    Vec4<scalar_t> dtv[IsKda ? NumChunk : 1];
    if constexpr (IsKda) {
        const Vec4<scalar_t>* dp = reinterpret_cast<const Vec4<scalar_t>*>(
            p.dt_bias + static_cast<int64_t>(hv) * K);
#pragma unroll
        for (int j = 0; j < NumChunk; ++j) {
            dtv[j] = dp[j * GroupSize + lane];
        }
    } else {
        dts = static_cast<float>(p.dt_bias[hv]);
    }

    const Vec4<scalar_t>* qp = reinterpret_cast<const Vec4<scalar_t>*>(
        p.q + (static_cast<int64_t>(bos) * p.H + h) * K);
    const Vec4<scalar_t>* kp = reinterpret_cast<const Vec4<scalar_t>*>(
        p.k + (static_cast<int64_t>(bos) * p.H + h) * K);
    const int64_t vec_step = static_cast<int64_t>(p.H) * VecK;

    Vec4<scalar_t> qc[NumChunk], kc[NumChunk], qx[NumChunk], kx[NumChunk];
    float ac = 0.0f, bc = 0.0f, an = 0.0f, bn = 0.0f;

#pragma unroll
    for (int j = 0; j < NumChunk; ++j) {
        qc[j] = qp[j * GroupSize + lane];
        kc[j] = kp[j * GroupSize + lane];
    }
    bc = static_cast<float>(p.b[static_cast<int64_t>(bos) * p.HV + hv]);
    if constexpr (!IsKda) {
        ac = static_cast<float>(p.a[static_cast<int64_t>(bos) * p.HV + hv]);
    }

    for (int t = 0; t < T_cur; ++t) {
        const int token = bos + t;

        if (t + 1 < T_cur) {
            const Vec4<scalar_t>* qn = qp + static_cast<int64_t>(t + 1) * vec_step;
            const Vec4<scalar_t>* kn = kp + static_cast<int64_t>(t + 1) * vec_step;
#pragma unroll
            for (int j = 0; j < NumChunk; ++j) {
                qx[j] = qn[j * GroupSize + lane];
                kx[j] = kn[j * GroupSize + lane];
            }
            bn = static_cast<float>(p.b[static_cast<int64_t>(token + 1) * p.HV + hv]);
            if constexpr (!IsKda) {
                an = static_cast<float>(p.a[static_cast<int64_t>(token + 1) * p.HV + hv]);
            }
        }

        Vec4<scalar_t> av[IsKda ? NumChunk : 1];
        if constexpr (IsKda) {
            const Vec4<scalar_t>* ap = reinterpret_cast<const Vec4<scalar_t>*>(
                p.a + (static_cast<int64_t>(token) * p.HV + hv) * K);
#pragma unroll
            for (int j = 0; j < NumChunk; ++j) {
                av[j] = ap[j * GroupSize + lane];
            }
        }

        const float beta_gate = 1.0f / (1.0f + __expf(-bc));
        float gate = 1.0f;
        if constexpr (!IsKda) {
            gate = __expf(-A * softplus_th(ac + dts, p.beta, p.inv_beta, p.threshold));
        }

        float hk[VRows];
        float qsq = 0.0f;
        float ksq = 0.0f;
#pragma unroll
        for (int r = 0; r < VRows; ++r) {
            hk[r] = 0.0f;
        }

#pragma unroll
        for (int j = 0; j < NumChunk; ++j) {
#pragma unroll
            for (int e = 0; e < kVec; ++e) {
                const float kv = static_cast<float>(kc[j].v[e]);
                const float qv = static_cast<float>(qc[j].v[e]);
                float g = gate;
                if constexpr (IsKda) {
                    const float x = static_cast<float>(av[j].v[e]) +
                                    static_cast<float>(dtv[j].v[e]);
                    g = __expf(-A * softplus_th(x, p.beta, p.inv_beta, p.threshold));
                }
                if constexpr (UseNorm) {
                    qsq += qv * qv;
                    ksq += kv * kv;
                }
#pragma unroll
                for (int r = 0; r < VRows; ++r) {
                    const float hg = hs[r][j][e] * g;
                    hs[r][j][e] = hg;
                    hk[r] += hg * kv;
                }
            }
        }

#pragma unroll
        for (int m = GroupSize / 2; m > 0; m >>= 1) {
#pragma unroll
            for (int r = 0; r < VRows; ++r) {
                hk[r] += __shfl_xor(hk[r], m, GroupSize);
            }
            if constexpr (UseNorm) {
                qsq += __shfl_xor(qsq, m, GroupSize);
                ksq += __shfl_xor(ksq, m, GroupSize);
            }
        }

        float inv_q = 1.0f;
        float inv_k = 1.0f;
        if constexpr (UseNorm) {
            inv_q = rsqrtf(qsq + 1.0e-6f);
            inv_k = rsqrtf(ksq + 1.0e-6f);
        }

        const int64_t vbase =
            (static_cast<int64_t>(token) * p.HV + hv) * p.V + v0;

        float coef[VRows];
#pragma unroll
        for (int r = 0; r < VRows; ++r) {
            const float vv = row_ok[r] ? static_cast<float>(p.v[vbase + r]) : 0.0f;
            coef[r] = (vv - hk[r] * inv_k) * beta_gate * inv_k;
        }

        float out[VRows];
#pragma unroll
        for (int r = 0; r < VRows; ++r) {
            out[r] = 0.0f;
        }

#pragma unroll
        for (int j = 0; j < NumChunk; ++j) {
#pragma unroll
            for (int e = 0; e < kVec; ++e) {
                const float kv = static_cast<float>(kc[j].v[e]);
                const float qv = static_cast<float>(qc[j].v[e]);
#pragma unroll
                for (int r = 0; r < VRows; ++r) {
                    const float hn = hs[r][j][e] + coef[r] * kv;
                    hs[r][j][e] = hn;
                    out[r] += hn * qv;
                }
            }
        }

#pragma unroll
        for (int m = GroupSize / 2; m > 0; m >>= 1) {
#pragma unroll
            for (int r = 0; r < VRows; ++r) {
                out[r] += __shfl_xor(out[r], m, GroupSize);
            }
        }

        if (lane == 0) {
#pragma unroll
            for (int r = 0; r < VRows; ++r) {
                if (row_ok[r]) {
                    p.o[vbase + r] = static_cast<scalar_t>(out[r] * inv_q * p.scale);
                }
            }
        }

        int64_t slot_out = static_cast<int64_t>(bos) + t;
        bool do_write = true;
        if (p.idx_write != nullptr) {
            const int s = p.idx_write[static_cast<int64_t>(n) * p.idx_stride + t];
            do_write = s >= 0;
            slot_out = s;
        }
        if (do_write) {
            float* db = p.state_out + slot_out * p.so_slot +
                        static_cast<int64_t>(hv) * p.so_hv;
#pragma unroll
            for (int r = 0; r < VRows; ++r) {
                if (row_ok[r]) {
                    f32x4* dp = reinterpret_cast<f32x4*>(
                        db + static_cast<int64_t>(v0 + r) * p.so_v);
#pragma unroll
                    for (int j = 0; j < NumChunk; ++j) {
                        st_state(dp + (j * GroupSize + lane), hs[r][j]);
                    }
                }
            }
        }

#pragma unroll
        for (int j = 0; j < NumChunk; ++j) {
            qc[j] = qx[j];
            kc[j] = kx[j];
        }
        ac = an;
        bc = bn;
    }
}

int env_group_size()
{
    static const int cached = [] {
        const char* e = std::getenv("AITER_FSG_GROUP_SIZE");
        if (e == nullptr) {
            e = std::getenv("AITER_FSG_KERNEL_VARIANT");
        }
        return e != nullptr ? std::atoi(e) : 0;
    }();
    return cached;
}

bool pair_supported(int gs, int nc)
{
    if (gs == 8) {
        return nc == 1 || nc == 2;
    }
    return (gs == 16 || gs == 32 || gs == 64) && nc == 2;
}

int pick_group_size(int K)
{
    const int e = env_group_size();
    if (e > 0 && K % (e * kVec) == 0 && pair_supported(e, K / (e * kVec))) {
        return e;
    }
    int gs = K / (kVec * 2);
    if (gs > 64) {
        gs = 64;
    }
    if (gs < 8) {
        gs = 8;
    }
    if (K % (gs * kVec) == 0 && pair_supported(gs, K / (gs * kVec))) {
        return gs;
    }
    return 0;
}

template <typename scalar_t, int NumChunk, int GroupSize, bool UseNorm, bool IsKda>
void launch_final(const FsgParams<scalar_t>& p, int N, hipStream_t stream)
{
    constexpr int RowsPerBlock = (kBlockThreads / GroupSize) * kVRows;
    const dim3 grid(static_cast<unsigned>(N),
                    static_cast<unsigned>(p.HV),
                    static_cast<unsigned>((p.V + RowsPerBlock - 1) / RowsPerBlock));
    vllm_fused_sigmoid_gating_delta_rule_update_kernel<
        scalar_t, NumChunk, GroupSize, kBlockThreads, kVRows, UseNorm, IsKda>
        <<<grid, dim3(kBlockThreads), 0, stream>>>(p);
}

template <typename scalar_t, int NumChunk, int GroupSize>
void launch_flags(const FsgParams<scalar_t>& p, int N, bool use_norm, bool is_kda,
                  hipStream_t stream)
{
    if (use_norm) {
        if (is_kda) {
            launch_final<scalar_t, NumChunk, GroupSize, true, true>(p, N, stream);
        } else {
            launch_final<scalar_t, NumChunk, GroupSize, true, false>(p, N, stream);
        }
    } else {
        if (is_kda) {
            launch_final<scalar_t, NumChunk, GroupSize, false, true>(p, N, stream);
        } else {
            launch_final<scalar_t, NumChunk, GroupSize, false, false>(p, N, stream);
        }
    }
}

template <typename scalar_t>
void launch_dispatch(const FsgParams<scalar_t>& p, int N, int gs, int nc,
                     bool use_norm, bool is_kda, hipStream_t stream)
{
    if (nc == 1) {
        launch_flags<scalar_t, 1, 8>(p, N, use_norm, is_kda, stream);
        return;
    }
    switch (gs) {
        case 8:  launch_flags<scalar_t, 2, 8>(p, N, use_norm, is_kda, stream);  return;
        case 16: launch_flags<scalar_t, 2, 16>(p, N, use_norm, is_kda, stream); return;
        case 32: launch_flags<scalar_t, 2, 32>(p, N, use_norm, is_kda, stream); return;
        default: launch_flags<scalar_t, 2, 64>(p, N, use_norm, is_kda, stream); return;
    }
}

} // namespace

std::vector<at::Tensor>
vllm_fused_sigmoid_gating_delta_rule_update(
    at::Tensor const &A_log,
    at::Tensor const &a,
    at::Tensor const &b,
    at::Tensor const &dt_bias,
    at::Tensor const &q,
    at::Tensor const &k,
    at::Tensor const &v,
    float beta,
    float threshold,
    std::optional<float> const &scale,
    std::optional<at::Tensor> const &initial_state_opt,
    bool inplace_final_state,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &ssm_state_indices,
    std::optional<at::Tensor> const &num_accepted_tokens,
    bool use_qk_l2norm_in_kernel,
    bool is_kda)
{
    TORCH_CHECK(q.is_cuda() && q.dim() == 4 && k.dim() == 4 && v.dim() == 4,
                "fsg_delta_rule: q/k/v must be 4D device tensors");
    TORCH_CHECK(initial_state_opt.has_value(),
                "fsg_delta_rule: initial_state is required");

    at::Tensor initial_state = *initial_state_opt;
    TORCH_CHECK(initial_state.dim() == 4 &&
                    initial_state.scalar_type() == at::ScalarType::Float &&
                    initial_state.stride(3) == 1,
                "fsg_delta_rule: initial_state must be fp32 [slots, HV, V, K], K contiguous");

    TORCH_CHECK(q.scalar_type() == at::ScalarType::Half ||
                    q.scalar_type() == at::ScalarType::BFloat16 ||
                    q.scalar_type() == at::ScalarType::Float,
                "fsg_delta_rule: q must be fp16/bf16/fp32");
    TORCH_CHECK(k.scalar_type() == q.scalar_type() && v.scalar_type() == q.scalar_type() &&
                    a.scalar_type() == q.scalar_type() && b.scalar_type() == q.scalar_type() &&
                    dt_bias.scalar_type() == q.scalar_type() &&
                    A_log.scalar_type() == at::ScalarType::Float,
                "fsg_delta_rule: activations must match q dtype, A_log must be fp32");

    const int64_t B_i64 = k.size(0);
    const int64_t T_i64 = k.size(1);
    const int64_t H_i64 = k.size(2);
    const int64_t K_i64 = k.size(3);
    const int64_t HV_i64 = v.size(2);
    const int64_t V_i64 = v.size(3);

    TORCH_CHECK(q.sizes() == k.sizes() && v.size(0) == B_i64 && v.size(1) == T_i64,
                "fsg_delta_rule: q/k/v leading dims mismatch");
    TORCH_CHECK(H_i64 > 0 && HV_i64 % H_i64 == 0 &&
                    initial_state.size(1) == HV_i64 &&
                    initial_state.size(2) == V_i64 &&
                    initial_state.size(3) == K_i64,
                "fsg_delta_rule: head dims inconsistent with initial_state");

    const int K = static_cast<int>(K_i64);
    const int group_size = pick_group_size(K);
    TORCH_CHECK(group_size != 0,
                "fsg_delta_rule: unsupported head_k_dim=", K,
                ", expect one of {32,64,128,256,512}");
    const int num_chunk = K / (group_size * kVec);

    auto A_log_c = A_log.contiguous();
    auto a_c = a.contiguous();
    auto b_c = b.contiguous();
    auto dt_c = dt_bias.contiguous();
    auto q_c = q.contiguous();
    auto k_c = k.contiguous();
    auto v_c = v.contiguous();

    at::Tensor cu_c;
    if (cu_seqlens.has_value()) {
        TORCH_CHECK(cu_seqlens->scalar_type() == at::ScalarType::Int && q.size(0) == 1,
                    "fsg_delta_rule: cu_seqlens must be int32 and q.shape[0] must be 1");
        cu_c = cu_seqlens->contiguous();
    }

    at::Tensor idx_c;
    int idx_stride = 1;
    if (ssm_state_indices.has_value()) {
        TORCH_CHECK(ssm_state_indices->scalar_type() == at::ScalarType::Int &&
                        (ssm_state_indices->dim() == 1 || ssm_state_indices->dim() == 2),
                    "fsg_delta_rule: ssm_state_indices must be int32 and 1D/2D");
        idx_c = ssm_state_indices->contiguous();
        idx_stride = idx_c.dim() == 2 ? static_cast<int>(idx_c.stride(0)) : 1;
    }

    at::Tensor acc_c;
    if (num_accepted_tokens.has_value()) {
        TORCH_CHECK(idx_c.defined() && idx_c.dim() == 2,
                    "fsg_delta_rule: spec decoding requires 2D ssm_state_indices");
        acc_c = num_accepted_tokens->scalar_type() == at::ScalarType::Int
                    ? num_accepted_tokens->contiguous()
                    : num_accepted_tokens->to(at::ScalarType::Int).contiguous();
    }

    auto output = torch::empty_like(v_c);
    if (output.numel() == 0) {
        return {output, initial_state};
    }

    at::Tensor final_state = inplace_final_state
        ? initial_state
        : torch::empty({T_i64, HV_i64, V_i64, K_i64}, initial_state.options());

    const int N = cu_c.defined() ? static_cast<int>(cu_c.size(0) - 1)
                                 : static_cast<int>(B_i64);
    const float scale_f = static_cast<float>(
        scale.has_value() ? *scale : std::pow(static_cast<double>(K_i64), -0.5));
    auto stream = at::hip::getCurrentHIPStream();

    AT_DISPATCH_FLOATING_TYPES_AND2(
        at::ScalarType::Half,
        at::ScalarType::BFloat16,
        q_c.scalar_type(),
        "vllm_fused_sigmoid_gating_delta_rule_update",
        [&] {
            FsgParams<scalar_t> p;
            p.A_log = A_log_c.data_ptr<float>();
            p.a = a_c.data_ptr<scalar_t>();
            p.b = b_c.data_ptr<scalar_t>();
            p.dt_bias = dt_c.data_ptr<scalar_t>();
            p.q = q_c.data_ptr<scalar_t>();
            p.k = k_c.data_ptr<scalar_t>();
            p.v = v_c.data_ptr<scalar_t>();
            p.o = output.data_ptr<scalar_t>();
            p.state_in = initial_state.data_ptr<float>();
            p.state_out = final_state.data_ptr<float>();
            p.cu_seqlens = cu_c.defined() ? cu_c.data_ptr<int32_t>() : nullptr;
            p.idx_read = idx_c.defined() ? idx_c.data_ptr<int32_t>() : nullptr;
            p.idx_write = (idx_c.defined() && inplace_final_state)
                              ? idx_c.data_ptr<int32_t>()
                              : nullptr;
            p.num_accepted = acc_c.defined() ? acc_c.data_ptr<int32_t>() : nullptr;
            p.si_slot = initial_state.stride(0);
            p.si_hv = initial_state.stride(1);
            p.si_v = initial_state.stride(2);
            p.so_slot = final_state.stride(0);
            p.so_hv = final_state.stride(1);
            p.so_v = final_state.stride(2);
            p.beta = beta;
            p.inv_beta = 1.0f / beta;
            p.threshold = threshold;
            p.scale = scale_f;
            p.T_total = static_cast<int>(T_i64);
            p.H = static_cast<int>(H_i64);
            p.HV = static_cast<int>(HV_i64);
            p.V = static_cast<int>(V_i64);
            p.h_ratio = static_cast<int>(HV_i64 / H_i64);
            p.idx_stride = idx_stride;

            launch_dispatch<scalar_t>(p, N, group_size, num_chunk,
                                      use_qk_l2norm_in_kernel, is_kda, stream.stream());
        });

    AITER_HIP_KERNEL_LAUNCH_CHECK();

    return {output, final_state};
}
