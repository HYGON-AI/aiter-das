# chunk_gated_delta_rule_fwd C++ API test

This test verifies both public paths against the same Triton reference:

1. the existing Python HIP API remains numerically accurate;
2. an external LibTorch executable can include `aiter_c_ops.h`, link
   `module_cpp_api.so`, call both `aiter::native::chunk_gated_delta_rule_fwd`
   and `aiter::native::chunk_gated_delta_rule_fwd_sglang`, and produce the
   same results, including SGLang's in-place state update.

Run from the AITER repository root after installing the built wheel:

```bash
bash op_tests/c_abi_tests/chunk_gated_delta_rule_fwd/build_and_run.sh .
```

The fixture covers FP16 and BF16 padded inputs with `g`, an initial FP32
state, final-state output, and saved new values. The supported HIP
specialization is `K=V=128`, `chunk_size=64`, and transposed state layout.
