# chunk_gated_delta_rule_fwd_kkt_solve_hip C++ API test

This test verifies the standalone KKT-solve HIP API against the Triton
SGLang reference:

1. the Python HIP API remains numerically accurate against the Triton
   reference implementation;
2. an external LibTorch executable can include `aiter_c_ops.h`, link
   `module_cpp_api.so`, call
   `aiter::native::chunk_gated_delta_rule_fwd_kkt_solve_hip`, and produce
   the same solved `A` tensor.

Run from the AITER repository root after installing the built wheel:

```bash
bash op_tests/c_abi_tests/chunk_gated_delta_rule_fwd_kkt_solve_hip/build_and_run.sh .
```

The fixture covers FP16 and BF16 inputs, FP32 `beta`/`g`, padded dense inputs,
and varlen inputs with `cu_seqlens`/`chunk_indices`. The supported fast HIP
specialization is `K=128` and `chunk_size=64`; the public API returns only
`A` with shape `[B, T, H, chunk_size]`.
