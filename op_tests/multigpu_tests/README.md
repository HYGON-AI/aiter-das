# Communication tests

Run commands from the AITER repository root. Select the participating devices
with `HIP_VISIBLE_DEVICES` before launching a test. Each process must use a
different GPU. The direct API tests fail if the required backend is unavailable.

## Interface and correctness tests

The CAR API test now lives in `op_tests/ci_tests/test_custom_allreduce_api.py`,
the copy CI discovers and runs; the `multigpu_tests` copy is kept until that
move is merged. From the repository root:

```bash
python op_tests/ci_tests/test_custom_allreduce_api.py
```

With at least four visible GPUs, this runs **TP2 followed by TP4**. It does not
run TP8 automatically, even on an eight-GPU machine. Each TP runs `reuse`,
`ar-boundaries` and `ar-precision` with both `off` and `auto`, then
`collectives`, `fusions` and `transport` with `off`: 18 independent torchrun
jobs in total. The launcher sets these algorithm policies itself; no
`AITER_AR_SMALL_MESSAGE` export is needed for the default matrix. Existing
registration-request and safe HCU copy-in checks remain enabled.

`AITER_AR_TP_SIZE=2` limits the default matrix to TP2 for a two-GPU CI allocation;
the usual CI allocation of four GPUs runs both sizes. An explicit
`--tp-size 2`, `--tp-size 4` or `--tp-size 8` runs only that size.
Use `--dry-run` to inspect the matrix without importing Torch or using GPUs.
Insufficient visible GPUs fail the test rather than silently skipping cases.

The default repeat counts are 100 (`--repeats`) and 20 (`--close-repeats`);
specialized boundary/precision loops retain their own case counts. Each job
has a 1,800-second timeout (`--timeout`). Raw logs, per-rank Python/native
provenance and `summary.json` go to a unique subdirectory of
`test_custom_allreduce_api_results/` in the working directory (`--output`
overrides the parent). Any failed job, timeout or missing rank completion
fails the launcher and preserves partial results.

CI registers this script separately from `test_custom_allreduce.py` in the
`multi_gpu_tests` table of the optest package, which only adds its four-GPU
allocation and exports `AITER_AR_TP_SIZE=4`. The original performance test and
its thresholds are unchanged. These operator tests do not replace
framework/model validation.

| Test | Coverage | Processes |
|---|---|---|
| `test_custom_allreduce_api.py --suite collectives` | Dimension-aware AG/RS, integer bit preservation, input validation, changing Graph inputs, close/recreate | 2, 4, 8 |
| `test_custom_allreduce_api.py --suite fusions` | RMSNorm/Gemma, padding/strides, FP8 mirrors/scales, MXFP4 packing, QK norm, Graph registration | 2, 4, 8 |
| `test_custom_allreduce_api.py --suite transport` | IPC selection, collective initialization failures, topology rejection, optional disabled-Fabric check | 2, 4, 8; 6 with `--tp6` |
| `test_custom_allreduce_api.py --suite reuse` | Immediate input reuse, changing eager/Graph inputs, exact FP16/BF16/FP32 sums and HCU copy-in protection | 2, 4, 8 |
| `test_custom_allreduce_api.py --suite ar-boundaries` | Mixed packet/LL/tile boundaries, two alternating Graphs, allocation cycles, rank submission skew and staging/admission capacity limits | 2, 4, 8 |
| `test_custom_allreduce_api.py --suite ar-precision` | Ordered FP32 sums, FP16/BF16 RNE ties, cancellation, Inf/NaN, subnormals, guarded tails and changing Graph inputs | 2, 4, 8 |
| `test_fused_ar_mhc_post.py` | AR+MHC one-stage/automatic/split entry points and Graph replay | 2, 4, 8 |
| `test_fused_qknorm_ar_rope.py` | Distributed QK statistics, RoPE, FP32 reference and fullgraph metadata | 2, 4, 8 |
| `test_parallel_groups.py` | TP/DP/PP/PCP/DCP/custom groups, public collectives, destruction and reinitialization | Exactly 4 |
| `test_quick_all_reduce_api.py --suite native` | Native QR handle APIs, quantization modes, BF16 cast policy, fused RMSNorm, Graph and resource reuse | 2, 4, 8 |
| `test_quick_all_reduce_api.py --suite communicator` | Python QR routing, admission checks, independent communicators and collective failure handling | 2, 4, 8 |
| `test_iris_comms.py --suite collectives` | Iris AG/RS, tail shapes, heap ownership/capacity and IPC lifetime | 2, 4, 8 |
| `test_iris_comms.py --suite fusion` | Iris RS/RMSNorm/FP8/AG fusion and independent FP8 conversion reference | 2, 4, 8 |
| `test_flydsl_quick_allreduce_int4.py` | Public INT4 API, small-payload BF16 policy, large payloads, Graph stress and performance | 2, 4, 8 |

For example:

```bash
HIP_VISIBLE_DEVICES=0,1 torchrun --standalone --nproc_per_node=2 \
  op_tests/ci_tests/test_custom_allreduce_api.py \
  --suite collectives --repeats 100 --close-repeats 20

HIP_VISIBLE_DEVICES=0,1 torchrun --standalone --nproc_per_node=2 \
  op_tests/ci_tests/test_custom_allreduce_api.py \
  --suite reuse --repeats 400

HIP_VISIBLE_DEVICES=4,5,6,7 torchrun --standalone --nproc_per_node=4 \
  op_tests/multigpu_tests/test_parallel_groups.py

python op_tests/test_comm_fusion_meta.py
```

The metadata test checks shape/dtype/stride and `torch.compile(fullgraph=True)`
without launching GPU kernels. Iris tests need the optional dependency pinned
in `requirements-triton-comms.txt`; INT4 needs a compatible Hygon FlyDSL build.
Run each `--suite` in a separate torchrun invocation so its process-group and
environment settings are isolated. CAR collectives/fusions/reuse and native QR use
`--repeats` (default 100); Iris uses `--repeats` and collectives also uses
`--cycles` (default 20). CAR transport and QR communicator retain 100 Graph
replays. CAR fusions accepts `--register off/on/both`; native QR accepts `--mode`.
The IPC tests run on one node. Fabric transport tests require a compatible
build and device configuration; use `super_node/` for multi-node testing.

Run `ar-precision` with `AITER_AR_SMALL_MESSAGE=off` or `auto`. It checks eager and eight
changing-input Graph replays with zero tolerance and emits per-rank output
digests. Its reference models the existing AITER JIT FP32 flush-to-zero mode
and RNE; it does not assume IEEE gradual underflow. NaN payloads are normalized
only for the digest. Compare digests from baseline and candidate builds using
the same test script and device configuration.

## Performance and broader regression

- `test_custom_allreduce_perf.py`: existing Custom AllReduce benchmark.
- `test_quick_all_reduce.py`: existing QR benchmark.
- `test_communication_api_perf.py`: representative TP2 CAR/fusion/MHC/QK-RoPE,
  HIP QR, Iris and parallel-group API latency. The `car` suite measures ordinary
  unquantized FP16/BF16/FP32 CAR and clone + RCCL over 4 KiB–32 MiB, in Graph
  and eager modes, including a changing-input exact check after timing.
  The `hip` suite measures GPU
  Graph time; `iris` and `groups_tp/groups_dp/groups_pp` measure synchronized
  eager wall and GPU time. Each case checks correctness before and after timing.
- `super_node/`: supernode benchmarks and transport/Graph tests.
- `../ci_tests/test_custom_allreduce.py`: FP16/BF16, shape and Graph/registration sweep.
- `../ci_tests/test_fused_ar_rms.py`: fused/split/quantized AR+RMSNorm correctness
  and timing. Use `-d fp16` or `-d bf16` to choose the dtype explicitly.
- The existing all-gather, reduce-scatter, QK norm, per-group quantization and
  GEMM/communication tests remain available for their respective APIs.

The INT4 test provides three suites:

```bash
HIP_VISIBLE_DEVICES=0,1 torchrun --standalone --nproc_per_node=2 \
  op_tests/multigpu_tests/test_flydsl_quick_allreduce_int4.py \
  --suite smoke --output /tmp/aiter_int4_smoke
```

Replace `smoke` with `large` for payloads through 320 MiB+16 B and 128 ordered
Graph replays, or `perf` for 32 KiB–64 MiB comparisons against HIP FP and RCCL.
`--grid-cap` limits the persistent grid. Results retain correctness metrics,
per-rank timing samples, collective median/P95/max and CV. With the default
small-payload policy, the public INT4 API uses HIP FP at <=32 KiB.

For the representative API benchmark, use two GPUs and provide an output directory:

```bash
AITER_ENABLE_SUPERNODE_AR=0 AITER_AR_TRANSPORT=ipc AITER_AR_ENABLE_REG_CAPTURE=0 \
AITER_QUICK_REDUCE_QUANTIZATION=NONE HIP_VISIBLE_DEVICES=0,1 \
torchrun --standalone --nproc_per_node=2 \
  op_tests/multigpu_tests/test_communication_api_perf.py \
  --suite hip --samples 30 --graph-ops 16 --output /tmp/comm_api_perf
```

Run each suite separately with a different output directory. Results include
all per-rank samples and collective median/P95/max/CV. Iris needs its optional
dependency; the group suites initialize AITER groups themselves. Usage and
published measurements are in [communication docs](../../docs/communication/communication_ops.md).

For ordinary CAR, use `--suite car --samples 30 --graph-ops 32` and a separate
output directory. Both paths preserve the input and allocate a new output;
CAR supports TP2/4/8; other representative suites still require TP2. Use
`--car-bytes 4096 65536 65552` and `--car-dtypes bfloat16` to select boundary
cases. `--trace` writes separate, untimed per-rank Graph traces.
The CAR fixture keeps every partial sum exactly representable for all four
input refreshes. TP8 uses rank/8 offsets (`input_fixture=dyadic_tp8_v2`);
TP2/TP4 retain the historical rank offsets. All CAR/RCCL checks use zero tolerance.
`--car-controls` adds D2D, fixed cached-input registration, and prefilled
uncached-staging kernel controls. The uncached control retains its native
input/output views and sets the capture stream explicitly. These fixed-input
controls do not authorize changing-input registration. Cached registration
may fail correctness; its failures are saved per rank and
produce a `PARTIAL_rank*.json` marker. Only passing rows enter `results.json`;
all recorded samples, including failed-control samples, are retained.
The RCCL reference includes `clone()`. The suite requests capture registration,
while gfx936/gfx938 preserve the communicator's safe input lifetime: traditional
paths use copy-in, and eligible LL/LL128 read only their local input before
publishing into peer scratch. Details and
current measurements are in [CustomAllreduce](../../docs/communication/custom_allreduce.md).
