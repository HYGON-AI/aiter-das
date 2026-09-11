# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT

import torch
import torch.nn.functional as F
from aiter.test_common import checkAllclose, benchmark, run_perftest
from aiter import dtypes
from aiter.ops.mqa_logits import mqa_logits
import argparse
from typing import Optional, Tuple

import os
import pandas as pd

if "CUDA_VISIBLE_DEVICES" not in os.environ:
    os.environ["CUDA_VISIBLE_DEVICES"] = "0"

torch.set_default_device("cuda")


def calc_diff(x: torch.Tensor, y: torch.Tensor) -> torch.Tensor:
    """Cosine similarity based difference metric for FP8 comparisons."""
    x, y = x.double(), y.double()
    denominator = (x * x + y * y).sum()
    sim = 2 * (x * y).sum() / denominator
    return 1 - sim


def per_custom_dims_cast_to_fp8(
    x: torch.Tensor, dims: Tuple[int, ...], use_ue8m0: bool
) -> Tuple[torch.Tensor, torch.Tensor]:
    """Cast tensor to FP8 along specified dimensions, returning scale."""
    excluded_dims = tuple([i for i in range(x.dim()) if i not in set(dims)])
    x_amax = x.abs().float().amax(dim=excluded_dims, keepdim=True).clamp(1e-4)
    sf = x_amax / 448.0

    def ceil_to_ue8m0(t: torch.Tensor) -> torch.Tensor:
        assert t.view(-1).amax().item() > 0
        return torch.pow(2.0, torch.ceil(torch.log2(t.abs())))

    sf = ceil_to_ue8m0(sf) if use_ue8m0 else sf
    x_scaled = (x * (1.0 / sf)).to(torch.float8_e4m3fn)
    return x_scaled, sf.squeeze()


def ref_mqa_logits(
    q: torch.Tensor,        # [q_seq_len, num_heads, head_dim]
    kv: torch.Tensor,       # [kv_seq_len, head_dim]
    weights: torch.Tensor,  # [q_seq_len, num_heads]
    cu_seqlen_ks: torch.Tensor,  # [q_seq_len]  int32, start indices
    cu_seqlen_ke: torch.Tensor,  # [q_seq_len]  int32, end indices
) -> torch.Tensor:
    """
    Reference PyTorch implementation of mqa_logits.
    
    Computes:
        score = einsum('mhd,nd->hmn', q, kv)   # [num_heads, q_seq_len, kv_seq_len]
        logits = (relu(score) * weights.T.unsqueeze(-1)).sum(dim=0)
        mask based on ks/ke ranges, fill -inf outside range
    """
    q_seq_len = q.shape[0]
    kv_seq_len = kv.shape[0]

    q_f = q.float()
    k_f = kv.float()

    # Build mask from ks/ke ranges
    mask_lo = torch.arange(0, kv_seq_len, device=q.device)[None, :] >= cu_seqlen_ks[:, None]
    mask_hi = torch.arange(0, kv_seq_len, device=q.device)[None, :] < cu_seqlen_ke[:, None]
    mask = mask_lo & mask_hi  # [q_seq_len, kv_seq_len]

    # Compute attention scores
    score = torch.einsum('mhd,nd->hmn', q_f, k_f)  # [num_heads, q_seq_len, kv_seq_len]

    # Apply ReLU and weighted sum over heads
    logits = (score.relu() * weights.T.unsqueeze(-1)).sum(dim=0)  # [q_seq_len, kv_seq_len]

    # Mask out-of-range positions
    logits = logits.masked_fill(~mask, float('-inf'))

    return logits


def ref_fp8_mqa_logits(
    q: torch.Tensor,
    kv: torch.Tensor,
    weights: torch.Tensor,
    cu_seqlen_ks: torch.Tensor,
    cu_seqlen_ke: torch.Tensor,
    kv_scale: Optional[torch.Tensor] = None,
) -> Tuple[torch.Tensor, torch.Tensor]:
    """
    Reference for FP8 mqa_logits.  q is fp8, kv is fp8 with optional per-channel scale.
    Returns (logits, cost).
    """
    q_f = q.float()
    k_f = kv.float()
    if kv_scale is not None:
        k_f = k_f * kv_scale[:, None]  # dequantize KV with per-channel scale

    logits = ref_mqa_logits(q_f, k_f, weights, cu_seqlen_ks, cu_seqlen_ke)
    cost = (cu_seqlen_ke - cu_seqlen_ks).clamp(min=0).sum()
    return logits, cost


def calc_mqa_logits_flops(
    cu_seqlen_ks: torch.Tensor,
    cu_seqlen_ke: torch.Tensor,
    num_heads: int,
    head_dim: int,
) -> float:
    """Estimate FLOPs from valid (ks, ke) ranges per query row."""
    start = cu_seqlen_ks.clamp(min=0)
    end = cu_seqlen_ke.clamp(min=0)
    valid_kv = (end - start).clamp(min=0).sum().item()
    return 2.0 * num_heads * head_dim * valid_kv


def run_mqa_logits_kernel(
    q_in: torch.Tensor,
    k_in: torch.Tensor,
    weights: torch.Tensor,
    ks: torch.Tensor,
    ke: torch.Tensor,
    q_seq_len: int,
    kv_seq_len: int,
    num_heads: int,
    head_dim: int,
    use_fp8: bool,
    kv_scale: Optional[torch.Tensor] = None,
) -> torch.Tensor:
    return mqa_logits(
        q_in, k_in, weights, ks, ke,
        q_seq_len, kv_seq_len, num_heads, head_dim,
        kv_scale, True, None,
    )


@benchmark()
def test_mqa_logits_correctness(
    q_seq_len: int,
    kv_seq_len: int,
    num_heads: int,
    head_dim: int,
    dtype_str: str,
    use_fp8: bool,
    cp_style: bool,
    enable_perf: bool = True,
    perf_iters: int = 11,
    perf_warmup: int = 2,
):
    """
    Correctness test for mqa_logits kernel.

    Args:
        q_seq_len: Number of query tokens.
        kv_seq_len: Number of key/value tokens.
        num_heads: Number of attention heads (must be in [1,2,4,8,16,32,64,128]).
        head_dim: Head dimension (must be 128).
        dtype_str: 'fp16' or 'bf16' for non-FP8 mode.
        use_fp8: Whether to use FP8 quantization.
        cp_style: Whether to use context-parallel style ks/ke (non-zero starts).
    """
    ret = {}

    assert head_dim == 128, "head_dim only supports 128"
    assert num_heads in [1, 2, 4, 8, 16, 32, 64, 128], \
        f"num_heads {num_heads} not in supported set"

    if use_fp8:
        dtype = torch.float8_e4m3fn
        compute_dtype = torch.bfloat16
    else:
        dtype = getattr(dtypes, dtype_str)
        compute_dtype = dtype

    # Generate test data
    Q = torch.randn(q_seq_len, num_heads, head_dim, device='cuda', dtype=compute_dtype)
    K = torch.randn(kv_seq_len, head_dim, device='cuda', dtype=compute_dtype)
    weights = torch.randn(q_seq_len, num_heads, device='cuda', dtype=torch.float32)

    if cp_style:
        # Context-parallel style: ks are non-zero, ke staggered
        ks = torch.zeros(q_seq_len, dtype=torch.int32, device='cuda')
        ke = torch.zeros(q_seq_len, dtype=torch.int32, device='cuda')
        chunk_size = q_seq_len // 2
        cp_size = kv_seq_len // q_seq_len if q_seq_len > 0 else 1
        cp_id = max(cp_size // 3, 1)
        for i in range(chunk_size):
            ke[i] = cp_id * chunk_size + i
            ke[i + chunk_size] = (cp_size * 2 - 1 - cp_id) * chunk_size + i
    else:
        # Standard: all rows end at kv_seq_len, staggered starts
        ks = torch.zeros(q_seq_len, dtype=torch.int32, device='cuda')
        ke = torch.full((q_seq_len,), kv_seq_len, dtype=torch.int32, device='cuda')

    # Prepare FP8 inputs if needed
    kv_scale = None
    if use_fp8:
        q_in = Q.to(torch.float8_e4m3fn)
        k_in, kv_scale = per_custom_dims_cast_to_fp8(K, (0,), False)
    else:
        q_in = Q
        k_in = K

    # Compute reference
    if use_fp8:
        ref_logits, _ = ref_fp8_mqa_logits(q_in, k_in, weights, ks, ke, kv_scale)
    else:
        ref_logits = ref_mqa_logits(q_in, k_in, weights, ks, ke)

    aiter_logits = run_mqa_logits_kernel(
        q_in, k_in, weights, ks, ke,
        q_seq_len, kv_seq_len, num_heads, head_dim, use_fp8, kv_scale,
    )
    torch.cuda.synchronize()

    ref_neginf_mask = (ref_logits == float('-inf'))
    neginf_mask = (aiter_logits == float('-inf'))
    mask_match = torch.equal(ref_neginf_mask.cpu(), neginf_mask.cpu())
    assert mask_match, "Mask mismatch between reference and kernel!"

    # Compare finite values
    ref_finite = ref_logits.masked_fill(ref_neginf_mask, 0.0)
    out_finite = aiter_logits.masked_fill(neginf_mask, 0.0)

    if use_fp8:
        diff = calc_diff(out_finite, ref_finite)
        assert diff < 1e-3, f"FP8 precision check failed! Diff: {diff:.4e}"
        ret["err"] = diff.item()
    else:
        max_err = (ref_finite - out_finite).abs().max()
        allclose = torch.allclose(out_finite, ref_finite, rtol=1e-3, atol=1e-3)
        assert allclose, f"{dtype_str} precision check failed! Max diff: {max_err:.4e}"
        ret["err"] = max_err.item()

    flops = calc_mqa_logits_flops(ks, ke, num_heads, head_dim)
    ret["flops"] = flops
    ret["ref_us"] = None
    ret["us"] = None
    ret["tflops"] = None

    if enable_perf:
        perf_kwargs = {"num_iters": perf_iters, "num_warmup": perf_warmup}
        if use_fp8:
            _, ref_us = run_perftest(
                ref_fp8_mqa_logits,
                q_in, k_in, weights, ks, ke, kv_scale,
                **perf_kwargs,
            )
        else:
            _, ref_us = run_perftest(
                ref_mqa_logits,
                q_in, k_in, weights, ks, ke,
                **perf_kwargs,
            )

        _, kernel_us = run_perftest(
            run_mqa_logits_kernel,
            q_in, k_in, weights, ks, ke,
            q_seq_len, kv_seq_len, num_heads, head_dim, use_fp8, kv_scale,
            **perf_kwargs,
        )

        ret["ref_us"] = ref_us
        ret["us"] = kernel_us
        ret["tflops"] = flops / kernel_us / 1e6 if kernel_us > 0 else 0.0

    ret["passed"] = True
    return ret


def print_summary_table(results):
    if not results:
        print("\nNo results to summarize.")
        return

    df = pd.DataFrame(results)
    n_pass = (df["status"] == "PASS").sum()
    n_fail = (df["status"] == "FAIL").sum()

    print("\n" + "=" * 72)
    print("MQA Logits Test Summary")
    print("=" * 72)
    print(f"Total: {len(df)}  |  PASS: {n_pass}  |  FAIL: {n_fail}")
    print("-" * 72)

    display_cols = [
        "dtype", "q_seq_len", "kv_seq_len", "num_heads", "head_dim",
        "fp8", "cp", "status", "err", "ref_us", "us", "tflops",
    ]
    if "error" in df.columns:
        display_cols.append("error")

    summary_df = df[display_cols].copy()
    summary_df["err"] = summary_df["err"].apply(
        lambda x: f"{x:.4e}" if pd.notna(x) else ""
    )
    for col in ("ref_us", "us"):
        summary_df[col] = summary_df[col].apply(
            lambda x: f"{x:.2f}" if pd.notna(x) else ""
        )
    summary_df["tflops"] = summary_df["tflops"].apply(
        lambda x: f"{x:.2f}" if pd.notna(x) else ""
    )

    print(summary_df.to_string(index=False))

    if n_fail > 0:
        failed = df[df["status"] == "FAIL"]
        print("\nFailed cases:")
        for _, row in failed.iterrows():
            print(
                f"  {row['dtype']} q={row['q_seq_len']} kv={row['kv_seq_len']} "
                f"heads={row['num_heads']} fp8={row['fp8']} cp={row['cp']} "
                f"-> {row.get('error', '')}"
            )


l_dtype = ["fp16", "bf16"]
l_q_seq_len = [1, 128, 512]
l_kv_seq_len = [64, 1024, 4096, 16384]
l_num_heads = [1, 8, 64]
l_head_dim = [128]
l_use_fp8 = [True, False]
l_cp_style = [False, True]

parser = argparse.ArgumentParser(
    formatter_class=argparse.RawTextHelpFormatter,
    description="MQA Logits Correctness Test",
)
parser.add_argument(
    "-d", "--dtype", type=str, choices=l_dtype,
    default=None, help="Data type (fp16/bf16).",
)
parser.add_argument(
    "-q", "--q_seq_len", type=int, default=None,
    help="Query sequence length.",
)
parser.add_argument(
    "-k", "--kv_seq_len", type=int, default=None,
    help="KV sequence length.",
)
parser.add_argument(
    "--num_heads", type=int, default=None,
    help="Number of attention heads.",
)
parser.add_argument(
    "--head_dim", type=int, default=128,
    help="Head dimension (default: 128).",
)
parser.add_argument(
    "--fp8", action="store_true", default=None,
    help="Use FP8 quantization.",
)
parser.add_argument(
    "--no-fp8", dest="fp8", action="store_false",
    help="Disable FP8 quantization.",
)
parser.add_argument(
    "--cp", action="store_true", default=None,
    help="Use context-parallel style ks/ke.",
)
parser.add_argument(
    "--no-perf", dest="perf", action="store_false",
    help="Disable kernel timing.",
)
parser.add_argument(
    "--perf-iters", type=int, default=11,
    help="Performance benchmark iterations (default: 11).",
)
parser.add_argument(
    "--perf-warmup", type=int, default=2,
    help="Performance benchmark warmup iterations (default: 2).",
)
parser.set_defaults(fp8=None, perf=True)

if __name__ == "__main__":
    args = parser.parse_args()

    dtypes_to_test = [args.dtype] if args.dtype else l_dtype
    q_lens = [args.q_seq_len] if args.q_seq_len else l_q_seq_len
    kv_lens = [args.kv_seq_len] if args.kv_seq_len else l_kv_seq_len
    heads = [args.num_heads] if args.num_heads else l_num_heads
    hdim = [args.head_dim] if args.head_dim else l_head_dim
    fp8_modes = [args.fp8] if args.fp8 is not None else l_use_fp8
    cp_modes = [args.cp] if args.cp is not None else l_cp_style

    results = []

    for dtype_str in dtypes_to_test:
        for q_len in q_lens:
            for kv_len in kv_lens:
                for nhead in heads:
                    for hd in hdim:
                        for fp8_mode in fp8_modes:
                            if fp8_mode and dtype_str != "bf16":
                                # FP8 mode doesn't use dtype parameter
                                continue
                            for cp_mode in cp_modes:
                                if cp_mode and q_len < 2:
                                    continue  # CP requires at least 2 tokens
                                if cp_mode and kv_len % q_len != 0:
                                    continue  # CP requires kv_len divisible by q_len

                                mode_str = f"dtype={dtype_str} q={q_len:4d} kv={kv_len:6d} "
                                mode_str += f"heads={nhead:3d} hdim={hd} "
                                mode_str += f"fp8={fp8_mode} cp={cp_mode}"

                                row = {
                                    "dtype": dtype_str,
                                    "q_seq_len": q_len,
                                    "kv_seq_len": kv_len,
                                    "num_heads": nhead,
                                    "head_dim": hd,
                                    "fp8": fp8_mode,
                                    "cp": cp_mode,
                                }

                                try:
                                    result = test_mqa_logits_correctness(
                                        q_len, kv_len, nhead, hd,
                                        dtype_str, fp8_mode, cp_mode,
                                        enable_perf=args.perf,
                                        perf_iters=args.perf_iters,
                                        perf_warmup=args.perf_warmup,
                                    )
                                    row["status"] = "PASS"
                                    row["err"] = result["err"]
                                    row["ref_us"] = result["ref_us"]
                                    row["us"] = result["us"]
                                    row["tflops"] = result["tflops"]
                                    perf_str = ""
                                    if result["us"] is not None:
                                        perf_str = (
                                            f" ref={result['ref_us']:.2f}us"
                                            f" kernel={result['us']:.2f}us"
                                            f" {result['tflops']:.2f} TFLOPS"
                                        )
                                    print(f"  PASS: {mode_str}{perf_str}")
                                except Exception as e:
                                    row["status"] = "FAIL"
                                    row["err"] = None
                                    row["ref_us"] = None
                                    row["us"] = None
                                    row["tflops"] = None
                                    row["error"] = str(e)
                                    print(f"  FAIL: {mode_str} -> {e}")

                                results.append(row)

    print_summary_table(results)
