# FLA chunk gated delta-rule forward

HIP implementation of `chunk_gated_delta_rule_fwd` for the FLA Triton
vLLM/SGLang frontends.

## Scope

- Public Python APIs:
  - `aiter.chunk_gated_delta_rule_fwd_vllm_hip_blockdim64`
  - `aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64`
  - compatibility aliases: `chunk_gated_delta_rule_fwd`,
    `chunk_gated_delta_rule_fwd_sglang`
- JIT module: `module_cpp_api` in `aiter/jit/optCompilerConfig.json`.
- Supported shape specialization: `headDimK == 128`, `headDimV == 128`,
  `chunk_size == 64`, `transpose_state_layout=True`.
- Active kernel paths: BV16, BV32, and gfx938 BV64/BV128 paths. All
  use 4 wavefronts per block and fp32 state accumulation. BV64/BV128 use the same
  frontend ABI and compile-time flag axes as BV16/BV32: fp16/bf16 input,
  BF16/FP32 state, G-only, GK-only, G+GK, and no-gate calls; optional
  initial/final state and `v_new`; padded or varlen indexing; and
  Natural/Exp2/SafeNatural exponent modes. The vLLM wrapper continues to
  require FP32 persistent state, while the SGLang wrapper accepts BF16 or
  FP32 state and keeps its fixed in-place SafeNatural contract.
- On 72-CU gfx938, auto uses `P=N*H`, where N is the batch size for padded
  inputs or the sequence count for varlen inputs. BV16/32/64/128 launch
  `8P/4P/2P/P` CTAs. Selection depends only on P: P<=9: BV16, 10..18: BV32,
  19..36: BV64, and P>=37: BV128. These empirical thresholds balance launch
  parallelism and work per CTA for common workloads. Other devices keep the
  established selection rules.
- `AITER_FLA_FORCE_BV=auto|0|16|32|64|128` is available for A/B testing.
  Forcing 64/128 requires gfx938, the supported head shape and transposed
  state layout. Unset and `0` use auto. Captured graphs retain the BV chosen
  during capture.
- Optional inputs covered by dispatch: `g`, `gk`, `initial_state`,
  `initial_state_indices`, `cu_seqlens`, `chunk_indices`, `chunk_offsets`.
  Prefer the upper framework to prepare/cache `chunk_indices` and
  `chunk_offsets` for varlen.
- Gate tensors `g` and `gk` must be fp32.
- BV128 assigns 32 value channels to each wave and keeps recurrent FP32
  state in registers. Its 32 KiB LDS is split between K (16 KiB) and shared
  W/U/V storage (16 KiB), with a swizzled U/V layout for vector accesses.
  A two-stage T32 pipeline overlaps data transfers with computation and
  prefetches the next chunk's W/G. Shared-memory reuse is synchronized, and
  invalid rows in the final chunk are masked.

## Files

```text
csrc/fla/
|-- chunk_gated_delta_rule_fwd.cu      # ATen wrapper and runtime dispatch
|-- docs/
|   `-- bv32_bv64_kernel_design.md     # BV32 analysis and BV64 design notes
|-- instances/                         # dtype-specific linked instances
|-- include/                           # kernel, traits, arch helpers
`-- README.md
```

Kernel implementation notes and the BV64 evolution are documented in
[`docs/bv32_bv64_kernel_design.md`](docs/bv32_bv64_kernel_design.md).

The active BV64 path is the gfx938 LIT/LTS LDS32 design. Four waves are spread
over BV (`BV16` per wave), and the recurrent state remains authoritative as
even/odd FP32 fragments in VGPR across chunks. GEMM0 converts only the current
BK32 fragment to BF16 and consumes W with `LIT=1`; GEMM1 consumes alternate K
and normal V matrix-DS fragments with `LIT=1,LTS=1`. The state conversion and
store packing are lane-local. U now uses a row-XOR D2L source map followed by
a q-even `ds_read_b128`; two full-EXEC `ds_bpermute_b32` operations per T16
stage distribute the high V4 to q-odd before FP32 residual arithmetic.

Its dynamic LDS layout is exactly 32 KiB:

```text
[ 0 KiB, 16 KiB): W current
                    low 8 KiB aliases T64xV64 U, then V matrix panels
[16 KiB, 32 KiB): K current
```

The low W half is reused only after all four waves have completed GEMM0 over
BK0/BK1. U and K are then issued direct-to-LDS in that order while GEMM0
continues on the high W half. Each T16 U region is read, synchronized, and
overwritten in place with the normal matrix-DS V layout. All four V fragments
are pulled into VGPR before W-next overwrites the alias. K uses one LDS buffer;
W-next overlaps GEMM1 and is published at the next chunk boundary.

GEMM0 uses a builtin-only, compiler-scheduled sequential W-read dataflow; W/K
DS reads remain compiler intrinsics so LLVM owns waitcnt inference. A/B testing
of the former D2/D3 lookahead paths and a four-read fill found no stable gain,
so the production path keeps the shorter live range of the sequential form. G is
carried across chunks behind W-next, allowing the next chunk to publish W at
`vmcnt(4)` while G remains in flight. Each GEMM0 BK also reuses its live BF16
state operands for the h snapshot store, avoiding a second state-pack pass. The
production resource/ISA gate for the current toolchain is 144 VGPR, 81
SGPR, zero private segment/spill, 32 KiB dynamic LDS, normal and alternate
  `ds_read_m32x16_b16`, q-even `ds_read_b128`, and LIT/LIT+LTS MMAC for the
  selected FP16/BF16 input type.
The HIP occupancy API reports two active 256-thread blocks per CU with 32768
bytes dynamic LDS. On the `N=32, NT=608, T=38912` target shape, the latest
hipprof snapshot reports about 1.949 ms kernel time, 86.6% TA memory-unit
busy, 43.2% TCP-to-TA data stall, 30.5% VALU busy, and a 14.9% normalized LDS
bank-conflict fraction. EA traffic is 0.840 GB read and 0.991 GB write per
dispatch, closely matching the 0.835 GB unique-input and 0.990 GB required
output bounds. The current bottleneck is therefore memory-front-end request
pressure/latency plus secondary LDS cost, not missing cache reuse or redundant
GMEM stores. See section 19.10 of the design notes for the PMC methodology and
next optimization order.

## Test

Run from the repository root in the DTK/HIP environment. The first run builds
`module_cpp_api` via JIT.

```bash
PYTHONPATH=. pytest -q op_tests/test_chunk_gated_hip_vllm.py
PYTHONPATH=. pytest -q op_tests/test_chunk_gated_hip_sglang.py
```

## Triton-to-HIP API Mapping

The HIP wrappers mirror the Triton vLLM/SGLang APIs and share the same keyword
arguments, so swapping the reference Triton kernel for the HIP kernel is a
one-line import + call-site change. The tests in
`op_tests/test_chunk_gated_hip_vllm.py` and
`op_tests/test_chunk_gated_hip_sglang.py` follow exactly this pattern, using the
Triton implementation as the numerical reference.

vLLM (`aiter.ops.triton.fla.vllm.chunk_delta_h.chunk_gated_delta_rule_fwd_h`
-> `aiter.chunk_gated_delta_rule_fwd_vllm_hip_blockdim64`):

```python
# Prefer computing varlen meta in the upper framework (and cache across layers),
# then pass them through.
# cu_seqlens: int32 or int64 (HIP IndexT from cu_seqlens).
# chunk_indices: int32 or int64; dtype need not match cu_seqlens (host NT only).
# chunk_offsets: always int64 (integer cumsum). If omitted/empty, HIP wrapper fills them.
# Prefer Triton helpers (or your framework cache) to prepare meta once:
# from aiter.ops.triton.fla.vllm.chunk_delta_h import (
#     prepare_chunk_indices, prepare_chunk_offsets,
# )
# chunk_indices = prepare_chunk_indices(cu_seqlens, chunk_size)
# chunk_offsets = prepare_chunk_offsets(cu_seqlens, chunk_size)

# Triton reference
from aiter.ops.triton.fla.vllm.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h,
)
h, v_new, final_state = triton_chunk_gated_delta_rule_fwd_h(
    k=k, w=w, u=u, g=g, gk=gk,
    initial_state=initial_state, initial_state_indices=initial_state_indices,
    output_final_state=output_final_state, chunk_size=chunk_size,
    save_new_value=save_new_value, cu_seqlens=cu_seqlens,
    chunk_indices=chunk_indices, use_exp2=use_exp2,
    transpose_state_layout=True,
)

# HIP replacement (same kwargs; returns (h, v_new, final_state))
import aiter
h, v_new, final_state = aiter.chunk_gated_delta_rule_fwd_vllm_hip_blockdim64(
    k, w, u, g=g, gk=gk,
    initial_state=initial_state, initial_state_indices=initial_state_indices,
    output_final_state=output_final_state, chunk_size=chunk_size,
    save_new_value=save_new_value, cu_seqlens=cu_seqlens,
    chunk_indices=chunk_indices,   # prefer framework-prepared
    chunk_offsets=chunk_offsets,   # prefer framework-prepared; required for varlen
    use_exp2=use_exp2,
    transpose_state_layout=True,
)
# compatibility alias: aiter.chunk_gated_delta_rule_fwd(...) is equivalent
```

SGLang (`aiter.ops.triton.fla.sglang.chunk_delta_h.chunk_gated_delta_rule_fwd_h`
-> `aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64`):

```python
# Prefer computing varlen meta in the upper framework (and cache across layers),
# then pass them through.
# cu_seqlens: int32 or int64 (HIP IndexT from cu_seqlens).
# chunk_indices: int32 or int64; dtype need not match cu_seqlens (host NT only).
# chunk_offsets: always int64 (integer cumsum). If omitted/empty, HIP wrapper fills them.
# Prefer Triton helpers (or your framework cache) to prepare meta once:
# from aiter.ops.triton.fla.sglang.chunk_delta_h import (
#     prepare_chunk_indices, prepare_chunk_offsets,
# )
# chunk_indices = prepare_chunk_indices(cu_seqlens, chunk_size)
# chunk_offsets = prepare_chunk_offsets(cu_seqlens, chunk_size)

# Triton reference
from aiter.ops.triton.fla.sglang.chunk_delta_h import (
    chunk_gated_delta_rule_fwd_h as triton_chunk_gated_delta_rule_fwd_h_sglang,
)
h, v_new = triton_chunk_gated_delta_rule_fwd_h_sglang(
    k=k, w=w, u=u, g=g, gk=gk,
    initial_state=state, initial_state_indices=initial_state_indices,
    output_final_state=output_final_state, chunk_size=chunk_size,
    save_new_value=save_new_value, cu_seqlens=cu_seqlens,
    chunk_indices=chunk_indices, use_exp2=use_exp2,
    transpose_state_layout=True,
)

# HIP replacement (in-place state update; returns (h, v_new))
import aiter
h, v_new = aiter.chunk_gated_delta_rule_fwd_sglang_hip_blockdim64(
    k, w, u, g=g, gk=gk,
    initial_state=state, initial_state_indices=initial_state_indices,
    output_final_state=output_final_state, chunk_size=chunk_size,
    save_new_value=save_new_value, cu_seqlens=cu_seqlens,
    chunk_indices=chunk_indices,   # prefer framework-prepared
    chunk_offsets=chunk_offsets,   # prefer framework-prepared; required for varlen
    use_exp2=use_exp2,
    transpose_state_layout=True,
)
# compatibility alias: aiter.chunk_gated_delta_rule_fwd_sglang(...) is equivalent
```

Notes:
- Argument order and keyword names match the Triton APIs; the HIP wrappers add
  an optional trailing `kernel_cfg` (currently unused), optional
  `chunk_offsets`, and default `transpose_state_layout=True`.
- vLLM returns `(h, v_new, final_state)`; when `save_new_value=False` or
  `output_final_state=False` the corresponding entry is `None`.
- SGLang updates every valid `initial_state` slot in place and returns only
  `(h, v_new)`. Its `output_final_state` argument is retained only for API
  signature compatibility: both the SGLang Triton launcher and this HIP path
  ignore its value and always perform the persistent-state update. In
  particular, passing `output_final_state=False` does not suppress writeback.
- Varlen meta: prefer the serving framework (vLLM/SGLang) to prepare and reuse
  `chunk_indices` / `chunk_offsets` (e.g. tensor cache across layers). HIP does
  not recompute them. If they are missing or empty, the HIP wrapper fills them
  once per call (internal helpers, not exported). `cu_seqlens` and
  `chunk_indices` may each be `int32` or `int64` and need not match; HIP
  dispatches `IndexT` from `cu_seqlens` only (`chunk_indices` supplies host-side
  NT). `chunk_offsets` is always `int64`. `initial_state_indices` must be
  `int32` and contiguous; HIP does not
  validate length==N or index OOB (caller-owned, same as SGLang).

## Benchmark

```bash
PYTHONPATH=. python op_tests/op_benchmarks/bench_chunk_gated_hip.py \
  --frontend vllm --batch 1 --seqlen 9008 --heads 8 --grouped-heads 2 \
  --k-dim 128 --v-dim 128 --dtype bf16 --varlen
```

Use `--frontend sglang` for the SGLang reference path.

For fixed workloads, compare variants with `AITER_FLA_FORCE_BV=16|32|64|128`
on a supported device. Sequence length, head layout, CTA scheduling tails,
and uneven varlen sequence lengths can shift which BV performs best.
After warming up, alternate variant order with the same inputs, tensor
addresses, and graph replay counts; reset persistent state between timing
groups. Recapture graphs after changing BV.

For profiler-driven timing, wrap the same benchmark command with `hipprof`.
The benchmark's printed timing is useful for smoke checks, but profiler output
is the source of truth for final performance claims.

## JIT Cache And Debug Info

To force a rebuild after source or flag changes:

```bash
rm -rf aiter/jit/build/module_cpp_api aiter/jit/module_cpp_api.so
```

The generated Ninja file does not currently emit header depfiles.  Therefore,
editing a header under `csrc/fla/include/` may otherwise leave a stale object.
For a targeted BV64 rebuild, explicitly clean the instance object before
building and relinking:

```bash
ninja -C aiter/jit/build/module_cpp_api/build -t clean \
  fla_hdimk128_hdimv128_bf16_statebf16_bv64.cuda.o
ninja -C aiter/jit/build/module_cpp_api/build \
  fla_hdimk128_hdimv128_bf16_statebf16_bv64.cuda.o \
  module_cpp_api.so
cp aiter/jit/build/module_cpp_api/build/module_cpp_api.so \
  aiter/jit/module_cpp_api.so
```

To add debug line information for SQTT source correlation:

```bash
AITER_JIT_DEBUG=1 \
AITER_JIT_DEBUG_MODULES=module_cpp_api \
AITER_JIT_DEBUG_FLAGS="-g" \
PYTHONPATH=. python op_tests/op_benchmarks/bench_chunk_gated_hip.py --no-verify
```

Clear the JIT cache before rebuilding with different debug flags.
