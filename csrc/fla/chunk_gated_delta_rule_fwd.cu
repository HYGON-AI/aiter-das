// SPDX-License-Identifier: MIT
//
// chunk_gated_delta_rule_fwd entry -- fills Delta_rule_params, dispatches on
// (input dtype, state dtype, block-V, exponent mode), and launches the kernel.
//
// Layout:
//   set_params_chunk_gated_delta_rule_fwd  : pointer / stride / flag plumbing
//   run_chunk_gated_delta_rule_fwd         : dtype + head-dim runtime dispatch
//   chunk_gated_delta_rule_fwd_*_hip_blockdim64 : ATen-level entries, called by pybind
//
// Kernel template specializations live in csrc/fla/instances/*.cu so each
// (input dtype, state dtype, block-V) combination is a separate TU.
//
// Calling-convention alignment with the triton reference
// (aiter/aiter/ops/triton/fla/sglang/chunk_delta_h.py):
//
//   * `h` is allocated as (B, NT, H, V, K) unconditionally -- the triton kernel
//     hard-codes this layout. `transpose_state_layout=true` is the only branch
//     currently routed through the dispatch.
//
//   * `final_state` is NOT a separately allocated tensor. The host aliases
//     `params.ht_ptr` to `initial_state.data_ptr()` and always updates every
//     valid persistent-state slot in place. `output_final_state` is ignored on
//     the SGLang path for signature compatibility, matching the Triton launcher
//     which hard-codes `INPLACE_UPDATE=True`. `initial_state` and
//     `initial_state_indices` are required to be passed together.
//
//   * Returned tuple is `{h, v_new}` (matches triton). When `save_new_value`
//     is false, `v_new` is returned as an empty `{0}` tensor so callers can
//     still unpack two values unconditionally.
//
//   * In varlen mode, Python supplies device `cu_seqlens` / `chunk_indices`
//     (each int32 or int64; dtypes need not match) and exclusive
//     `chunk_offsets` (int64). HIP dispatches IndexT from cu_seqlens only;
//     chunk_indices is host-side NT = size(0) and is not read by the kernel.
#include "fla.h"

#include <torch/all.h>
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <cstdlib>
#include <cstdint>
#include <cstring>

////////////////////////////////////////////////////////////////////////////////////////////////////
// Small helpers / argument check macros.
////////////////////////////////////////////////////////////////////////////////////////////////////
#define CHECK_DEVICE(x)                                                       \
    TORCH_CHECK(x.is_cuda(), #x " must be on CUDA/HIP device")
#define CHECK_SHAPE(x, ...)                                                   \
    TORCH_CHECK(x.sizes() == torch::IntArrayRef({__VA_ARGS__}),               \
                #x " must have shape (" #__VA_ARGS__ ")")
#define CHECK_CONTIGUOUS(x)                                                   \
    TORCH_CHECK(x.is_contiguous(), #x " must be contiguous")

static inline int ceildiv(int a, int b) { return (a + b - 1) / b; }

// Empirical selection for the 72-CU gfx938 target. P=N*H gives 8P/4P/2P/P
// CTAs for BV16/32/64/128. These count-only thresholds favor common workloads;
// AITER_FLA_FORCE_BV allows fixed-shape tuning without extra auto branches.
static int fla_select_bv_gfx938_72(int64_t p)
{
    if (p <= 9) return 16;
    if (p <= 18) return 32;
    if (p <= 36) return 64;
    return 128;
}

static void check_same_device(const at::Tensor &reference,
                              const at::Tensor &tensor,
                              const char *name)
{
    TORCH_CHECK(tensor.device() == reference.device(),
                name, " must be on the same device as k");
}

////////////////////////////////////////////////////////////////////////////////////////////////////
// set_params_chunk_gated_delta_rule_fwd
//
// Pack every input pointer, stride, dimension, and flag into Delta_rule_params.
// Strides are recorded in *elements*.
//
// On the SGLang path the caller supplies the same persistent-state tensor as
// both h0 and ht, so those pointers alias. The vLLM path supplies a distinct ht.
////////////////////////////////////////////////////////////////////////////////////////////////////
static void set_params_chunk_gated_delta_rule_fwd(
    FLA_NAMESPACE::Delta_rule_params &params,
    // dims
    const int B, const int T, const int H, const int Hg,
    const int K, const int V, const int BT, const int NT,
    const int N, const int state_rows,
    // inputs
    const at::Tensor &k, const at::Tensor &w, const at::Tensor &u,
    const std::optional<at::Tensor> &g,
    const std::optional<at::Tensor> &gk,
    // outputs
    at::Tensor &h, at::Tensor &v_new, at::Tensor &final_state,
    // state
    const std::optional<at::Tensor> &initial_state,
    const std::optional<at::Tensor> &initial_state_indices,
    // varlen device pointers (cu_seqlens: IndexT; chunk_offsets: int64)
    void *cu_seqlens_d, void *chunk_offsets_d,
    // flags
    bool is_varlen, bool index_is_int64, bool is_bf16, bool store_final_state,
    bool save_new_value, bool use_exp2, bool transpose_state_layout)
{
    // Reset all fields.
    params = {};

    const bool has_initial_state         = initial_state.has_value() && initial_state.value().defined();
    const bool has_initial_state_indices = initial_state_indices.has_value() && initial_state_indices.value().defined();
    const bool has_final_state           = final_state.defined();

    // --- flags ---
    params.is_varlen                  = is_varlen;
    params.index_is_int64             = index_is_int64;
    params.is_bf16                    = is_bf16;
    params.use_g                      = g.has_value()  && g.value().defined();
    params.use_gk                     = gk.has_value() && gk.value().defined();
    params.use_initial_state          = has_initial_state;
    params.use_initial_state_indices  = has_initial_state_indices;
    params.store_final_state          = store_final_state && has_final_state;
    params.save_new_value             = save_new_value && v_new.defined();
    params.use_exp2                   = use_exp2;
    params.transpose_state_layout     = transpose_state_layout;

    // --- dimensions ---
    params.B          = B;
    params.T          = T;
    params.H          = H;
    params.Hg         = Hg;
    params.K          = K;
    params.V          = V;
    params.BT         = BT;
    params.NT         = NT;
    params.N          = N;
    params.state_rows = state_rows;

    // --- k: (B, T, Hg, K) or (total_k, Hg, K) ---
    params.k_ptr         = k.data_ptr();
    params.k_row_stride  = (is_varlen && k.dim() == 3) ? k.stride(0) : k.stride(1);
    params.k_head_stride = k.stride(-2);                            // stride over Hg (== K when packed)
    if (!is_varlen) params.k_batch_stride = k.stride(0);

    // --- w: (B, T, H, K) or (total_k, H, K) ---
    params.w_ptr         = w.data_ptr();
    params.w_row_stride  = (is_varlen && w.dim() == 3) ? w.stride(0) : w.stride(1);
    params.w_head_stride = w.stride(-2);
    if (!is_varlen) params.w_batch_stride = w.stride(0);

    // --- u (value): (B, T, H, V) or (total_k, H, V) ---
    params.u_ptr         = u.data_ptr();
    params.u_row_stride  = (is_varlen && u.dim() == 3) ? u.stride(0) : u.stride(1);
    params.u_head_stride = u.stride(-2);
    if (!is_varlen) params.u_batch_stride = u.stride(0);

    // --- g: (B, T, H) or (total_k, H) ---
    if (params.use_g) {
        const auto &g_t = g.value();
        params.g_ptr = g_t.data_ptr();
        params.g_row_stride = (is_varlen && g_t.dim() == 2) ? g_t.stride(0) : g_t.stride(1);
        if (!is_varlen) params.g_batch_stride = g_t.stride(0);
    }

    // --- gk: (B, T, H, K) or (total_k, H, K) ---
    if (params.use_gk) {
        const auto &gk_t = gk.value();
        params.gk_ptr = gk_t.data_ptr();
        params.gk_row_stride  = (is_varlen && gk_t.dim() == 3) ? gk_t.stride(0) : gk_t.stride(1);
        params.gk_head_stride = gk_t.stride(-2);
        if (!is_varlen) params.gk_batch_stride = gk_t.stride(0);
    }

    // --- h (chunked hidden state output): always (B, NT, H, V, K) ---
    params.h_ptr          = h.data_ptr();
    params.h_batch_stride = h.stride(0);
    params.h_chunk_stride = h.stride(1);
    params.h_head_stride  = h.stride(2);

    // --- v_new (residual value output): (B, T, H, V) or (total_k, H, V) ---
    if (params.save_new_value) {
        params.v_new_ptr         = v_new.data_ptr();
        params.v_new_row_stride  = (is_varlen && v_new.dim() == 3) ? v_new.stride(0) : v_new.stride(1);
        params.v_new_head_stride = v_new.stride(-2);
        if (!is_varlen) params.v_new_batch_stride = v_new.stride(0);
    }

    // --- initial_state: (state_rows, H, V, K)  (transpose_state_layout=true) ---
    if (has_initial_state) {
        const auto &h0 = initial_state.value();
        params.h0_ptr          = h0.data_ptr();
        params.h0_batch_stride = h0.stride(0);
        params.h0_head_stride  = h0.stride(1);

    }

    // --- final_state: (state_rows, H, V, K) ---
    if (params.store_final_state) {
        params.ht_ptr          = final_state.data_ptr();
        params.ht_batch_stride = final_state.stride(0);
        params.ht_head_stride  = final_state.stride(1);
    }

    // --- initial_state_indices: (N,) ---
    if (has_initial_state_indices) {
        params.initial_state_indices = static_cast<const int *>(
            initial_state_indices.value().data_ptr());
    }

    // --- varlen ---
    params.cu_seqlens    = cu_seqlens_d;
    params.chunk_offsets = chunk_offsets_d;
}

////////////////////////////////////////////////////////////////////////////////////////////////////
// run_chunk_gated_delta_rule_fwd
//
// Lightweight host dispatcher. Heavy template instantiations are split into
// flat TUs under csrc/fla/instances/, keyed by
// (input dtype, state dtype, BV).
////////////////////////////////////////////////////////////////////////////////////////////////////
void run_chunk_gated_delta_rule_fwd(
    FLA_NAMESPACE::Delta_rule_params &params, hipStream_t stream,
    bool use_safe_exp, bool state_is_bf16)
{
    TORCH_CHECK(params.K == 128 && params.V == 128,
                "chunk_gated_delta_rule_fwd: only headDimK==128 && headDimV==128 is supported");
    TORCH_CHECK(!(use_safe_exp && params.use_exp2),
                "chunk_gated_delta_rule_fwd: safe natural exp and exp2 cannot be enabled together");

    const auto exp_mode = use_safe_exp
        ? FLA_NAMESPACE::ExpMode::SafeNatural
        : (params.use_exp2 ? FLA_NAMESPACE::ExpMode::Exp2
                           : FLA_NAMESPACE::ExpMode::Natural);

    // Development/A-B override. "auto" (or unset) uses the runtime selector;
    // 16/32 force the established paths; 64/128 require gfx938.
    // This is host-only and does not change the public Python ABI.
    const char *force_bv_env = std::getenv("AITER_FLA_FORCE_BV");
    int force_bv = 0;
    if (force_bv_env != nullptr && std::strcmp(force_bv_env, "auto") != 0 &&
        std::strcmp(force_bv_env, "0") != 0) {
        if (std::strcmp(force_bv_env, "16") == 0) {
            force_bv = 16;
        } else if (std::strcmp(force_bv_env, "32") == 0) {
            force_bv = 32;
        } else if (std::strcmp(force_bv_env, "64") == 0) {
            force_bv = 64;
        } else if (std::strcmp(force_bv_env, "128") == 0) {
            force_bv = 128;
        } else {
            TORCH_CHECK(false,
                        "AITER_FLA_FORCE_BV must be auto, 0, 16, 32, 64, or 128; got ",
                        force_bv_env);
        }
    }

    // The device guard in the public wrapper has already selected k's device.
    const auto *props = at::cuda::getCurrentDeviceProperties();
    const bool wide_target_eligible =
        props != nullptr && std::strncmp(props->gcnArchName, "gfx938", 6) == 0 &&
        params.transpose_state_layout &&
        params.K == 128 && params.V == 128;
    TORCH_CHECK((force_bv != 64 && force_bv != 128) || wide_target_eligible,
                "AITER_FLA_FORCE_BV=", force_bv, " requires gfx938, "
                "transpose_state_layout=true, and K=V=128");
    int selected_bv = force_bv;
    if (selected_bv == 0) {
        const int64_t p = int64_t(params.N) * params.H;
        const bool is_gfx92a_120 =
            props != nullptr && props->multiProcessorCount == 120 &&
            std::strncmp(props->gcnArchName, "gfx92a", 6) == 0;
        // Measured boundary for 120-CU gfx92a; retain the gfx936 fallback.
        const int bv32_threshold = is_gfx92a_120 ? 16 : 12;
        selected_bv = wide_target_eligible && 2 * p >= 128 ? 64
                    : (p < bv32_threshold ? 16 : 32);
        if (wide_target_eligible && props->multiProcessorCount == 72) {
            selected_bv = fla_select_bv_gfx938_72(p);
        }
    }
    if (selected_bv == 128) {
        if (params.is_bf16) {
            if (state_is_bf16) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv128(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv128(
                    params, stream, exp_mode);
            }
        } else {
            if (state_is_bf16) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv128(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv128(
                    params, stream, exp_mode);
            }
        }
        return;
    }
    if (selected_bv == 64) {
        if (params.is_bf16) {
            if (state_is_bf16) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv64(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv64(
                    params, stream, exp_mode);
            }
        } else {
            if (state_is_bf16) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv64(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv64(
                    params, stream, exp_mode);
            }
        }
        return;
    }

    const bool use_bv32 = selected_bv == 32;

    if (params.is_bf16) {
        if (state_is_bf16) {
            if (use_bv32) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv32(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_bf16_bv16(
                    params, stream, exp_mode);
            }
        } else {
            if (use_bv32) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv32(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_bf16_state_fp32_bv16(
                    params, stream, exp_mode);
            }
        }
    } else {
        if (state_is_bf16) {
            if (use_bv32) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv32(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_bf16_bv16(
                    params, stream, exp_mode);
            }
        } else {
            if (use_bv32) {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv32(
                    params, stream, exp_mode);
            } else {
                FLA_NAMESPACE::run_chunk_gated_delta_rule_fwd_fp16_state_fp32_bv16(
                    params, stream, exp_mode);
            }
        }
    }
}

////////////////////////////////////////////////////////////////////////////////////////////////////
// chunk_gated_delta_rule_fwd_*_hip_blockdim64 -- torch-facing entries.
// Bound in csrc/pybind/fla_pybind.cu.
//
// Shared implementation for the vLLM and SGLang wrappers. vLLM returns
// {h, v_new, final_state}; SGLang returns {h, v_new}.
//
// In varlen mode, Python supplies device `cu_seqlens` / `chunk_indices`
// (each int32 or int64; dtypes need not match) and exclusive `chunk_offsets`
// (int64). IndexT is dispatched from cu_seqlens; chunk_indices is host-side
// NT via size(0) only.
static std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_common(
    at::Tensor const &k,
    at::Tensor const &w,
    at::Tensor const &u,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &gk,
    std::optional<at::Tensor> const &initial_state,
    std::optional<at::Tensor> const &initial_state_indices,
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    std::optional<at::Tensor> const &chunk_offsets,
    bool const use_exp2,
    bool const transpose_state_layout,
    bool const inplace_final_state,
    bool const use_safe_exp)
{
    // --- dtype checks ---
    const auto dtype = k.dtype();
    TORCH_CHECK(dtype == torch::kFloat16 || dtype == torch::kBFloat16,
                "chunk_gated_delta_rule_fwd only supports fp16 and bf16");
    TORCH_CHECK(w.dtype() == dtype, "k and w must have the same dtype");
    TORCH_CHECK(u.dtype() == dtype, "k and u must have the same dtype");
    const bool is_bf16 = (dtype == torch::kBFloat16);

    TORCH_CHECK(chunk_size == 64,
                "chunk_gated_delta_rule_fwd currently only supports chunk_size == 64");

    // --- device + contiguity checks ---
    CHECK_DEVICE(k);
    CHECK_DEVICE(w);
    CHECK_DEVICE(u);
    TORCH_CHECK(k.stride(-1) == 1, "k must have contiguous last dimension");
    TORCH_CHECK(w.stride(-1) == 1, "w must have contiguous last dimension");
    TORCH_CHECK(u.stride(-1) == 1, "u must have contiguous last dimension");

    const bool is_varlen = cu_seqlens.has_value() && cu_seqlens.value().defined();
    const bool has_h0     = initial_state.has_value() && initial_state.value().defined();
    const bool has_h0_idx = initial_state_indices.has_value() && initial_state_indices.value().defined();

    // The kernel carries raw pointers and does not perform device switching.
    // Keep all optional tensors on k's device, then make the current HIP
    // device match it before querying the architecture and obtaining the
    // launch stream.
    check_same_device(k, w, "w");
    check_same_device(k, u, "u");
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(k));
    if (g.has_value() && g.value().defined()) {
        check_same_device(k, g.value(), "g");
    }
    if (gk.has_value() && gk.value().defined()) {
        check_same_device(k, gk.value(), "gk");
    }
    if (has_h0) {
        check_same_device(k, initial_state.value(), "initial_state");
    }
    if (has_h0_idx) {
        check_same_device(k, initial_state_indices.value(),
                          "initial_state_indices");
    }
    if (cu_seqlens.has_value() && cu_seqlens.value().defined()) {
        check_same_device(k, cu_seqlens.value(), "cu_seqlens");
    }
    if (chunk_indices.has_value() && chunk_indices.value().defined()) {
        check_same_device(k, chunk_indices.value(), "chunk_indices");
    }
    if (chunk_offsets.has_value() && chunk_offsets.value().defined()) {
        check_same_device(k, chunk_offsets.value(), "chunk_offsets");
    }

    if (inplace_final_state) {
        TORCH_CHECK(has_h0,
                    "chunk_gated_delta_rule_fwd_sglang requires initial_state "
                    "because final state is updated in place");
        TORCH_CHECK(has_h0_idx,
                    "chunk_gated_delta_rule_fwd_sglang requires int32 initial_state_indices");
    }

    if (g.has_value() && g.value().defined()) {
        const auto &g_t = g.value();
        TORCH_CHECK(g_t.dtype() == torch::kFloat32,
                    "g must be float32 because the HIP kernel reads it as float");
        TORCH_CHECK(g_t.stride(-1) == 1,
                    "g must have contiguous head dimension");
    }
    if (gk.has_value() && gk.value().defined()) {
        const auto &gk_t = gk.value();
        TORCH_CHECK(gk_t.dtype() == torch::kFloat32,
                    "gk must be float32 because the HIP kernel reads it as float");
        TORCH_CHECK(gk_t.stride(-1) == 1,
                    "gk must have contiguous K dimension");
    }

    TORCH_CHECK(k.dim() == 4 || (is_varlen && k.dim() == 3),
                "k must be (B,T,Hg,K), or packed (total_k,Hg,K) with cu_seqlens");
    TORCH_CHECK(w.dim() == k.dim() && u.dim() == k.dim(),
                "k, w, and u must use matching padded/packed ranks");

    // --- dimensions ---
    int B, T, H, Hg, Kdim, Vdim, N, NT, state_rows, max_seqlen;

    if (!is_varlen) {
        // Padded mode: k (B, T, Hg, K), w (B, T, H, K), u (B, T, H, V).
        B          = k.size(0);
        T          = k.size(1);
        Hg         = k.size(2);
        Kdim       = k.size(3);
        H          = u.size(2);
        Vdim       = u.size(3);
        N          = B;
        NT         = ceildiv(T, chunk_size);
        max_seqlen = T;

        CHECK_SHAPE(k, B, T, Hg, Kdim);
        CHECK_SHAPE(w, B, T, H,  Kdim);
        CHECK_SHAPE(u, B, T, H,  Vdim);

        if (g.has_value() && g.value().defined()) {
            CHECK_SHAPE(g.value(), B, T, H);
            CHECK_DEVICE(g.value());
        }
        if (gk.has_value() && gk.value().defined()) {
            CHECK_SHAPE(gk.value(), B, T, H, Kdim);
            CHECK_DEVICE(gk.value());
        }
    } else {
        // Python `_ensure_varlen_meta` supplies device cu_seqlens /
        // chunk_indices (host NT only) and exclusive chunk_offsets (int64).
        const auto &cu = cu_seqlens.value();
        TORCH_CHECK(chunk_offsets.has_value() && chunk_offsets.value().defined(),
                    "chunk_gated_delta_rule_fwd: chunk_offsets required for varlen");
        TORCH_CHECK(chunk_indices.has_value() && chunk_indices.value().defined(),
                    "chunk_gated_delta_rule_fwd: chunk_indices required for varlen");
        const auto &offsets = chunk_offsets.value();
        const auto &indices = chunk_indices.value();
        TORCH_CHECK(cu.scalar_type() == at::kInt || cu.scalar_type() == at::kLong,
                    "cu_seqlens must be int32 or int64");
        // chunk_indices is only used for NT = size(0); element dtype is unused.
        // Accept int32 or int64 independently of cu_seqlens (callers may mismatch).
        TORCH_CHECK(indices.scalar_type() == at::kInt || indices.scalar_type() == at::kLong,
                    "chunk_indices must be int32 or int64 (got ",
                    indices.scalar_type(), ")");
        TORCH_CHECK(offsets.scalar_type() == at::kLong,
                    "chunk_offsets must be int64 (got ", offsets.scalar_type(), ")");
        TORCH_CHECK(cu.dim() == 1 && cu.size(0) >= 2 && cu.stride(0) == 1,
                    "cu_seqlens must be a contiguous 1D tensor with at least two elements");
        TORCH_CHECK(offsets.dim() == 1 && offsets.stride(0) == 1,
                    "chunk_offsets must be a contiguous 1D tensor");
        TORCH_CHECK(indices.dim() == 2 && indices.size(1) == 2 &&
                        indices.stride(1) == 1,
                    "chunk_indices must have shape (NT, 2) with a contiguous last dimension");
        CHECK_DEVICE(cu);
        CHECK_DEVICE(offsets);
        CHECK_DEVICE(indices);

        const bool packed = k.dim() == 3;
        B    = packed ? int(cu.size(0) - 1) : int(k.size(0));
        T    = packed ? int(k.size(0)) : int(k.size(1));
        Hg   = k.size(-2);
        Kdim = k.size(-1);
        H    = u.size(-2);
        Vdim = u.size(-1);
        N    = cu.size(0) - 1;
        NT   = int(indices.size(0));
        max_seqlen = T;

        if (packed) {
            CHECK_SHAPE(k, T, Hg, Kdim);
            CHECK_SHAPE(w, T, H,  Kdim);
            CHECK_SHAPE(u, T, H,  Vdim);
        } else {
            TORCH_CHECK(k.size(0) * k.size(1) >= T,
                        "padded varlen k does not contain cu_seqlens[-1] tokens");
            CHECK_SHAPE(k, B, k.size(1), Hg, Kdim);
            CHECK_SHAPE(w, B, k.size(1), H,  Kdim);
            CHECK_SHAPE(u, B, k.size(1), H,  Vdim);
        }

        if (g.has_value() && g.value().defined()) {
            const auto &g_t = g.value();
            CHECK_DEVICE(g_t);
            if (packed) {
                CHECK_SHAPE(g_t, T, H);
            } else {
                CHECK_SHAPE(g_t, B, k.size(1), H);
            }
        }
        if (gk.has_value() && gk.value().defined()) {
            const auto &gk_t = gk.value();
            CHECK_DEVICE(gk_t);
            if (packed) {
                CHECK_SHAPE(gk_t, T, H, Kdim);
            } else {
                CHECK_SHAPE(gk_t, B, k.size(1), H, Kdim);
            }
        }
    }

    // --- general checks ---
    TORCH_CHECK(Kdim == 128 && Vdim == 128,
                "chunk_gated_delta_rule_fwd: only headDimK==128 && headDimV==128 is supported");
    TORCH_CHECK(H % Hg == 0,
                "Number of query heads (H=", H,
                ") must be divisible by number of key heads (Hg=", Hg, ")");

    // --- initial_state shape check (h is (state_rows, H, V, K) per triton) ---
    state_rows = N;
    bool state_is_bf16 = false;
    if (has_h0) {
        const auto &s = initial_state.value();
        CHECK_DEVICE(s);
        TORCH_CHECK(s.dim() == 4,
                    "initial_state must be a 4D (state_rows, H, V, K) tensor");
        if (inplace_final_state) {
            TORCH_CHECK(s.dtype() == torch::kFloat32 || s.dtype() == torch::kBFloat16,
                        "SGLang initial_state must be float32 or bfloat16");
        } else {
            TORCH_CHECK(s.dtype() == torch::kFloat32,
                        "vLLM initial_state must be float32");
        }
        state_is_bf16 = (s.dtype() == torch::kBFloat16);
        state_rows = s.size(0);
        TORCH_CHECK(s.size(1) == H, "initial_state head dim mismatch (expected H=", H, ")");
        TORCH_CHECK(s.size(2) == Vdim && s.size(3) == Kdim,
                    "initial_state must have shape (state_rows, H, V, K) = (",
                    state_rows, ", ", H, ", ", Vdim, ", ", Kdim, "); "
                    "transpose_state_layout=false is not yet implemented");
        TORCH_CHECK(s.stride(3) == 1 && s.stride(2) == Kdim &&
                        s.stride(1) == int64_t(Vdim) * Kdim,
                    "initial_state must be dense in its H/V/K dimensions; got strides ",
                    s.strides());
    }
    if (has_h0_idx) {
        const auto &idx = initial_state_indices.value();
        TORCH_CHECK(idx.dtype() == torch::kInt32, "initial_state_indices must be int32");
        CHECK_DEVICE(idx);
        TORCH_CHECK(idx.dim() == 1, "initial_state_indices must be a 1D tensor");
        TORCH_CHECK(idx.numel() >= N,
                    "initial_state_indices must contain at least N=", N,
                    " entries; got ", idx.numel());
        TORCH_CHECK(idx.stride(0) == 1, "initial_state_indices must be contiguous");
#if 0
        // Disabled: idx.min()/max() launch ATen reduce kernels and .item() syncs
        // every call. Caller is responsible for in-range indices (matches Triton).
        if (idx.numel() > 0) {
            const int idx_min = idx.min().item<int>();
            const int idx_max = idx.max().item<int>();
            TORCH_CHECK(idx_min >= 0 && idx_max < state_rows,
                        "initial_state_indices values must be in [0, state_rows); got min=",
                        idx_min, ", max=", idx_max, ", state_rows=", state_rows);
        }
#endif
    }

    // --- allocate outputs ---
    // h shape: (B, NT, H, V, K) -- always V-then-K to match the triton kernel.
    at::Tensor h = torch::empty({B, NT, H, Vdim, Kdim}, k.options());

    // v_new is allocated only when requested; otherwise an empty placeholder
    // keeps the return tuple shape stable.
    at::Tensor v_new;
    if (save_new_value) {
        v_new = torch::empty_like(u);
    }

    // SGLang owns a persistent pool and always writes valid slots in place.
    // output_final_state remains in its public signature for compatibility but
    // only controls the out-of-place vLLM result.
    const bool store_final_state = inplace_final_state || output_final_state;
    at::Tensor final_state;
    if (store_final_state) {
        if (inplace_final_state) {
            final_state = initial_state.value();
        } else {
            final_state = torch::empty({state_rows, H, Vdim, Kdim},
                                       k.options().dtype(torch::kFloat32));
        }
    }

    // --- varlen: IndexT from cu_seqlens; chunk_offsets always int64 ---
    void *cu_seqlens_d    = nullptr;
    void *chunk_offsets_d = nullptr;
    bool index_is_int64   = false;
    if (is_varlen) {
        const auto &cu = cu_seqlens.value();
        index_is_int64 = (cu.scalar_type() == at::kLong);
        cu_seqlens_d    = cu.data_ptr();
        chunk_offsets_d = chunk_offsets.value().data_ptr();
    }

    // --- fill params (SGLang final_state already aliases initial_state) ---
    FLA_NAMESPACE::Delta_rule_params params;
    set_params_chunk_gated_delta_rule_fwd(
        params,
        /*dims*/         B, max_seqlen, H, Hg, Kdim, Vdim, chunk_size, NT, N, state_rows,
        /*inputs*/       k, w, u, g, gk,
        /*outputs*/      h, v_new, final_state,
        /*state*/        initial_state, initial_state_indices,
        /*varlen ptrs*/  cu_seqlens_d, chunk_offsets_d,
        /*flags*/        is_varlen, index_is_int64, is_bf16,
                         /*store_final_state*/ store_final_state,
                         save_new_value, use_exp2,
                         transpose_state_layout);

    // --- launch ---
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    run_chunk_gated_delta_rule_fwd(params, stream, use_safe_exp, state_is_bf16);

    // Return {h, v_new} -- matches triton's chunk_gated_delta_rule_fwd_h. When
    // save_new_value is false, v_new is a {0}-sized placeholder so each public
    // wrapper keeps a stable return arity.
    at::Tensor v_new_out = v_new.defined() ? v_new : at::empty({0}, u.options());
    if (inplace_final_state) {
        return {h, v_new_out};
    }
    at::Tensor final_state_out = final_state.defined()
        ? final_state
        : at::empty({0}, k.options().dtype(torch::kFloat32));
    return {h, v_new_out, final_state_out};
}

std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
    at::Tensor const &k,
    at::Tensor const &w,
    at::Tensor const &u,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &gk,
    std::optional<at::Tensor> const &initial_state,
    std::optional<at::Tensor> const &initial_state_indices,
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    std::optional<at::Tensor> const &chunk_offsets,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    return chunk_gated_delta_rule_fwd_common(
        k, w, u, g, gk, initial_state, initial_state_indices,
        output_final_state, chunk_size, save_new_value, cu_seqlens,
        chunk_indices, chunk_offsets, use_exp2, transpose_state_layout,
        /*inplace_final_state*/ false, /*use_safe_exp*/ false);
}

std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
    at::Tensor const &k,
    at::Tensor const &w,
    at::Tensor const &u,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &gk,
    std::optional<at::Tensor> const &initial_state,
    std::optional<at::Tensor> const &initial_state_indices,
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    std::optional<at::Tensor> const &chunk_offsets,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    (void)output_final_state;
    (void)use_exp2;
    TORCH_CHECK(transpose_state_layout,
                "chunk_gated_delta_rule_fwd_sglang only supports transpose_state_layout=true");

    return chunk_gated_delta_rule_fwd_common(
        k, w, u, g, gk, initial_state, initial_state_indices,
        /*output_final_state*/ true, chunk_size, save_new_value, cu_seqlens,
        chunk_indices, chunk_offsets, /*use_exp2*/ false, /*transpose_state_layout*/ true,
        /*inplace_final_state*/ true, /*use_safe_exp*/ true);
}


////////////////////////////////////////////////////////////////////////////////////////////////////
// Backward-compatible aliases for older Python/tests. New code should call the explicit
// *_hip_blockdim64 entry points so frontend/backend/specialization are visible at the API.
////////////////////////////////////////////////////////////////////////////////////////////////////
std::vector<at::Tensor>
chunk_gated_delta_rule_fwd(
    at::Tensor const &k,
    at::Tensor const &w,
    at::Tensor const &u,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &gk,
    std::optional<at::Tensor> const &initial_state,
    std::optional<at::Tensor> const &initial_state_indices,
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    std::optional<at::Tensor> const &chunk_offsets,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    return chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
        k, w, u, g, gk, initial_state, initial_state_indices,
        output_final_state, chunk_size, save_new_value, cu_seqlens,
        chunk_indices, chunk_offsets, use_exp2, transpose_state_layout);
}

std::vector<at::Tensor>
chunk_gated_delta_rule_fwd_sglang(
    at::Tensor const &k,
    at::Tensor const &w,
    at::Tensor const &u,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &gk,
    std::optional<at::Tensor> const &initial_state,
    std::optional<at::Tensor> const &initial_state_indices,
    bool const output_final_state,
    int const chunk_size,
    bool const save_new_value,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    std::optional<at::Tensor> const &chunk_offsets,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    return chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
        k, w, u, g, gk, initial_state, initial_state_indices,
        output_final_state, chunk_size, save_new_value, cu_seqlens,
        chunk_indices, chunk_offsets, use_exp2, transpose_state_layout);
}
