# Shared HIP kernel launcher regression

Run from the AITER repository with the container's HIP SDK. The test depends
only on repository headers and HIP; it does not import temporary scripts.

```bash
hipcc -std=c++20 --offload-arch=gfx946 -DAITER_ENABLE_MULTIDIE=1 \
  -Icsrc/include -I3rdparty/composable_kernel/include \
  op_tests/gfx946_tests/common_launch/test_hip_kernel_launch.cpp -o /tmp/test_hip_kernel_launch
/tmp/test_hip_kernel_launch
```

For gfx936/gfx938 use that target and omit `-DAITER_ENABLE_MULTIDIE=1`.
Configure the target device or Perf Model before running (single `sb`, dual
`sbx2`). The executable initializes HIP then removes `GPU_CHIP`.

The five policies share typed argument conversion (int32 to int64, float to
double), dynamic LDS, and a non-default stream. Coverage includes auto with
one/five TGs, off, linear chunk 2, invalid mode/chunk/mask, and TopK/Sum empty
grid validation order. Expected counts: 29 on hardware/single XCD, 39 on dual
XCD. PMD TG routing must be checked separately in StatLog; eager results do
not establish Graph support.

Operator numerical regressions remain in `silu_and_mul`, `quant`,
`grouped_quant`, `moe_topk`, `moe_sorting_sum` (`--op sum`), and `normal_gemm`.
Existing per-family environment variables are unchanged. Logs now report all
three grid/block dimensions and dynamic shared bytes consistently.
