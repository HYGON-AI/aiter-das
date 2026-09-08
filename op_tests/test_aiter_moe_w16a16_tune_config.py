# SPDX-License-Identifier: MIT
"""Tune helper for W16A16 MOE_C configs.

Examples:
  HIP_VISIBLE_DEVICES=4 python op_tests/test_aiter_moe_w16a16_tune_config.py
  HIP_VISIBLE_DEVICES=4 python op_tests/test_aiter_moe_w16a16_tune_config.py --write-configs
  HIP_VISIBLE_DEVICES=4 python op_tests/test_aiter_moe_w16a16_tune_config.py --moe-c-candidates 304:304,168:175
"""

import argparse
import copy
import json
import os
import subprocess
import sys
import tempfile
from pathlib import Path
from typing import Any, Callable, Dict, Iterable, List, Optional, Tuple

os.environ.setdefault("AMDGCN_USE_BUFFER_OPS", "1")
os.environ.setdefault("TRITON_FUSED_MOE_CHUNK_SIZE", "16384")

SCRIPT_DIR = Path(__file__).resolve().parent
if str(SCRIPT_DIR) not in sys.path:
    sys.path.insert(0, str(SCRIPT_DIR))

import pandas as pd
import torch

import aiter
from benchmark_moe_w16a16_aiter_gemm import (
    align_for_moe_c_method,
    sorted_ids_for_moe_c_mode,
    w16a16_marlin_weight,
)
from aiter import dtypes
from aiter.fused_moe import fused_topk, torch_moe
from aiter.moe import (
    AiterMoeConfig,
    MoeQuantType,
    MoeSolutionType,
    aiter_moe,
    aiter_moe_shfl_weight,
    get_aiter_moe_config,
)
from aiter import silu_and_mul

DEFAULT_M_LIST = "1,2,4,8,16,32,64,128,256,512,1024,2048,4096,8192"
DEFAULT_MODEL_DIM = 768
DEFAULT_INTER_DIM = 1536
DEFAULT_NUM_EXPERTS = 8
DEFAULT_TOPK = 2

W16A16_MOE_C_DECODE_MODES = "300,301,302,303,304,305,306,307,308,309,310,311,312,313,314,315"
W16A16_MOE_C_PREFILL_MODES = (
    "10,11,12,13,14,15,16,17,18,21,"
    "32,33,34,35,36,37,38,39,40,41,42,44,46,"
    "103,104,106,114,115,117,120,121,123,"
    "128,129,130,132,133,136,141,143,146,156,"
    "168,175,177,181,188,189,190,192,193,195"
)
W16A16_MOE_C_ASM_PREFILL_MODES = "1000"
W16A16_MOE_C_PREFILL_AND_ASM_MODES = f"{W16A16_MOE_C_PREFILL_MODES},{W16A16_MOE_C_ASM_PREFILL_MODES}"
W16A16_MOE_C_ALL_MODES = f"{W16A16_MOE_C_PREFILL_AND_ASM_MODES},{W16A16_MOE_C_DECODE_MODES}"
W16A16_MOE_C_DECODE_THRESHOLD = 128
W16A16_MOE_C_MODE_BM = {
    10: 16,
    11: 16,
    12: 16,
    13: 32,
    14: 32,
    15: 32,
    16: 32,
    17: 64,
    18: 64,
    21: 64,
    32: 16,
    33: 16,
    34: 16,
    35: 32,
    36: 32,
    37: 32,
    38: 32,
    39: 32,
    40: 64,
    41: 64,
    42: 64,
    44: 64,
    46: 64,
    103: 16,
    104: 32,
    106: 16,
    114: 64,
    115: 32,
    117: 64,
    120: 32,
    121: 64,
    123: 64,
    128: 16,
    129: 16,
    130: 16,
    132: 32,
    133: 32,
    136: 64,
    141: 32,
    143: 32,
    146: 64,
    156: 16,
    168: 32,
    175: 32,
    177: 64,
    181: 64,
    188: 16,
    189: 16,
    190: 16,
    192: 32,
    193: 32,
    195: 64,
    300: 16,
    301: 16,
    302: 16,
    303: 16,
    304: 16,
    305: 16,
    306: 16,
    307: 16,
    308: 16,
    309: 16,
    310: 16,
    311: 16,
    312: 16,
    313: 16,
    314: 16,
    315: 16,
    # hsa/gfx936/w16a16_new currently exposes mode=1000 with tile 128x256x64.
    1000: 128,
}


def parse_int_list(text: str) -> List[int]:
    return [int(x) for x in text.replace(";", ",").split(",") if x.strip()]


def mode_to_block_size_m(mode: int) -> int:
    try:
        return W16A16_MOE_C_MODE_BM[mode]
    except KeyError as exc:
        raise ValueError(f"Unsupported W16A16 MOE_C mode: {mode}") from exc


def modes_for_preset(preset: str, m: int, decode_threshold: int) -> List[int]:
    if preset == "auto":
        preset = "eligible"
    preset_modes = {
        "eligible": W16A16_MOE_C_ALL_MODES,
        "all": W16A16_MOE_C_ALL_MODES,
        "decode": W16A16_MOE_C_DECODE_MODES,
        "prefill": W16A16_MOE_C_PREFILL_AND_ASM_MODES,
    }[preset]
    modes = parse_int_list(preset_modes)
    if preset == "all":
        return modes

    eligible = [mode for mode in modes if m > mode_to_block_size_m(mode)]
    if eligible:
        return eligible

    if preset == "eligible":
        return parse_int_list(W16A16_MOE_C_DECODE_MODES)

    min_bm = min(mode_to_block_size_m(mode) for mode in modes)
    return [mode for mode in modes if mode_to_block_size_m(mode) == min_bm]


def dtype_from_name(name: str) -> torch.dtype:
    if name in ("bf16", "bfloat16", "torch.bfloat16"):
        return dtypes.bf16
    if name in ("fp16", "float16", "torch.float16"):
        return torch.float16
    raise ValueError(f"Unsupported dtype: {name}")


def dtype_to_config_name(dtype: torch.dtype) -> str:
    if dtype is torch.bfloat16:
        return "torch.bfloat16"
    if dtype is torch.float16:
        return "torch.float16"
    return str(dtype)


def current_arch() -> str:
    prop = torch.cuda.get_device_properties(torch.cuda.current_device())
    arch = getattr(prop, "gcnArchName", "") or getattr(prop, "gcn_arch_name", "")
    if arch:
        return str(arch).split(":", 1)[0]
    return f"sm_{prop.major}{prop.minor}"


def make_inputs(
    m: int,
    k: int,
    n: int,
    e: int,
    topk: int,
    dtype: torch.dtype,
    seed: int,
) -> Dict[str, torch.Tensor]:
    torch.manual_seed(seed)
    hidden_states = torch.randn((m, k), device="cuda", dtype=dtype) / 10
    w1 = torch.randn((e, 2 * n, k), device="cuda", dtype=dtype) / 2
    w2 = torch.randn((e, k, n), device="cuda", dtype=dtype) / 2
    score = torch.randn((m, e), device="cuda", dtype=dtype)
    topk_weights, topk_ids = fused_topk(hidden_states, score, topk, True)
    return {
        "hidden_states": hidden_states,
        "w1": w1,
        "w2": w2,
        "topk_weights": topk_weights,
        "topk_ids": topk_ids,
    }


def bench_us(fn, warmup: int, iters: int) -> Tuple[torch.Tensor, float]:
    out = None
    for _ in range(warmup):
        out = fn()
    torch.cuda.synchronize()
    start = torch.cuda.Event(enable_timing=True)
    end = torch.cuda.Event(enable_timing=True)
    start.record()
    for _ in range(iters):
        out = fn()
    end.record()
    end.synchronize()
    return out, start.elapsed_time(end) * 1000.0 / iters


def parse_moe_c_candidates(text: Optional[str]) -> List[Dict[str, int]]:
    if not text:
        return []
    candidates = []
    for item in text.replace(";", ",").split(","):
        item = item.strip()
        if not item:
            continue
        parts = [int(x) for x in item.split(":")]
        if len(parts) not in (2, 3, 4):
            raise ValueError(
                "MOE_C candidate must be MODE1:MODE2[:BM1[:BM2]], "
                f"got {item}"
            )
        mode1, mode2 = parts[:2]
        bm1 = parts[2] if len(parts) >= 3 else mode_to_block_size_m(mode1)
        bm2 = parts[3] if len(parts) >= 4 else mode_to_block_size_m(mode2)
        if not pair_is_single_sort_compatible(bm1, bm2):
            raise ValueError(
                f"MOE_C candidate requires BM1 >= BM2 and BM1 % BM2 == 0, got {item}"
            )
        candidates.append(
            {
                "MODE1": mode1,
                "MODE2": mode2,
                "BM1": bm1,
                "BM2": bm2,
            }
        )
    return candidates


def make_moe_c_candidate_grid(
    mode1_list: List[int],
    mode2_list: List[int],
) -> Iterable[Dict[str, int]]:
    for mode1 in mode1_list:
        for mode2 in mode2_list:
            bm1 = mode_to_block_size_m(mode1)
            bm2 = mode_to_block_size_m(mode2)
            yield {
                "MODE1": mode1,
                "MODE2": mode2,
                "BM1": bm1,
                "BM2": bm2,
            }


def pair_is_single_sort_compatible(bm1: int, bm2: int) -> bool:
    return bm1 >= bm2 and bm1 % bm2 == 0


def make_pair_config(mode1: int, bm1: int, mode2: int, bm2: int) -> Dict[str, Any]:
    bm1 = int(bm1)
    bm2 = int(bm2)
    if not pair_is_single_sort_compatible(bm1, bm2):
        raise ValueError(f"BM pair is not single-sort compatible: {bm1}, {bm2}")
    return {
        "SORT_BLOCK_SIZE_M": bm1,
        "GEMM1_CONFIG": {
            "MODE": int(mode1),
            "BLOCK_SIZE_M": bm1,
            "DELTA": 1,
        },
        "GEMM2_CONFIG": {
            "MODE": int(mode2),
            "BLOCK_SIZE_M": bm2,
            "DELTA": bm1 // bm2,
        },
    }


def make_stage_candidate_grid(
    mode_list: List[int],
) -> Iterable[Dict[str, int]]:
    for mode in mode_list:
        bm = mode_to_block_size_m(mode)
        yield {
            "MODE": mode,
            "BLOCK_SIZE_M": bm,
        }


def get_base_config(
    m: int,
    k: int,
    n: int,
    e: int,
    topk: int,
    dtype: torch.dtype,
    use_shuffle: int,
) -> Optional[AiterMoeConfig]:
    status, cfg = get_aiter_moe_config(
        M=m,
        E=e,
        N1=2 * n,
        N2=k,
        K=k,
        top_k=topk,
        block_size=0,
        dtype=dtype,
        quant_type=MoeQuantType.W16A16,
        spec_sol_type=MoeSolutionType.MOE_C,
        use_shuffle=use_shuffle,
    )
    return cfg if status else None


def make_empty_moe_c_config() -> AiterMoeConfig:
    return AiterMoeConfig(
        quant_type=MoeQuantType.W16A16,
        solution_type=MoeSolutionType.MOE_C,
        need_shuffle=True,
        need_shuffle_scale=False,
        config={"GEMM1_CONFIG": {}, "GEMM2_CONFIG": {}},
    )


def expand_candidate_configs(
    base: AiterMoeConfig,
    moe_c_candidates: Iterable[Dict[str, int]],
) -> Iterable[Tuple[str, AiterMoeConfig]]:
    if base.solution_type == MoeSolutionType.MOE_C and moe_c_candidates:
        for cand in moe_c_candidates:
            cfg = copy.deepcopy(base)
            cfg.config = copy.deepcopy(base.config or {})
            cfg.config.update(make_pair_config(cand["MODE1"], cand["BM1"], cand["MODE2"], cand["BM2"]))
            name = config_name(cfg)
            yield name, cfg
        return

    yield config_name(base), base


def config_name(cfg: AiterMoeConfig) -> str:
    if cfg.solution_type == MoeSolutionType.MOE_C and cfg.config:
        g1 = cfg.config.get("GEMM1_CONFIG", {})
        g2 = cfg.config.get("GEMM2_CONFIG", {})
        return (
            f"{g1.get('MODE')}:{g2.get('MODE')}:"
            f"{g1.get('BLOCK_SIZE_M')}:{g2.get('BLOCK_SIZE_M')}:"
            f"{g1.get('DELTA', 1)}:{g2.get('DELTA', 1)}"
        )
    return str(cfg.solution_type)


def run_one(
    data: Dict[str, torch.Tensor],
    cfg: AiterMoeConfig,
    warmup: int,
    iters: int,
    check: bool,
    atol: float,
    rtol: float,
    routed_scaling_factor: float,
) -> Dict[str, Any]:
    w1_input = data["w1"]
    w2_input = data["w2"]
    if cfg.need_shuffle:
        w1_input, w2_input = aiter_moe_shfl_weight(data["w1"], data["w2"], cfg)

    def fn() -> torch.Tensor:
        return aiter_moe(
            data["hidden_states"],
            w1_input,
            w2_input,
            data["topk_weights"],
            data["topk_ids"],
            cfg,
            inplace=False,
            activation="silu",
            w1_scale=None,
            w2_scale=None,
            w1_zp=None,
            w2_zp=None,
            a1_scale=None,
            a2_scale=None,
            block_shape=None,
            global_num_experts=data["w1"].shape[0],
            expert_map=None,
            routed_scaling_factor=routed_scaling_factor,
            use_weight_shuffle=cfg.need_shuffle,
        )

    out, us = bench_us(fn, warmup=warmup, iters=iters)
    row: Dict[str, Any] = {
        "us": us,
        "accuracy": "unchecked",
        "max_abs_diff": None,
        "max_rel_diff": None,
    }
    if check:
        ref = torch_moe(
            data["hidden_states"],
            data["w1"],
            data["w2"],
            data["topk_weights"],
            data["topk_ids"],
        )
        torch.cuda.synchronize()
        diff = (ref - out).abs()
        max_abs = float(diff.max().item())
        max_ref = float(ref.abs().max().item())
        max_rel = max_abs / max(max_ref, 1.0e-6)
        passed = bool(torch.allclose(ref, out, rtol=rtol, atol=atol))
        row.update(
            {
                "accuracy": "passed" if passed else "failed",
                "max_abs_diff": max_abs,
                "max_rel_diff": max_rel,
            }
        )
    return row


def run_candidate_subprocess(
    candidate_name: str,
    cfg: AiterMoeConfig,
    m: int,
    k: int,
    n: int,
    e: int,
    topk: int,
    dtype_name: str,
    seed: int,
    warmup: int,
    iters: int,
    check: bool,
    atol: float,
    rtol: float,
    routed_scaling_factor: float,
    timeout_s: int,
) -> Dict[str, Any]:
    payload = {
        "candidate": candidate_name,
        "cfg": {
            "quant_type": cfg.quant_type,
            "solution_type": cfg.solution_type,
            "need_shuffle": cfg.need_shuffle,
            "need_shuffle_scale": cfg.need_shuffle_scale,
            "config": cfg.config,
        },
        "shape": {
            "m": m,
            "k": k,
            "n": n,
            "e": e,
            "topk": topk,
            "dtype": dtype_name,
            "seed": seed,
        },
        "run": {
            "warmup": warmup,
            "iters": iters,
            "check": check,
            "atol": atol,
            "rtol": rtol,
            "routed_scaling_factor": routed_scaling_factor,
        },
    }
    with tempfile.TemporaryDirectory(prefix="w16a16_tune_") as tmpdir:
        payload_path = Path(tmpdir) / "payload.json"
        result_path = Path(tmpdir) / "result.json"
        with payload_path.open("w") as f:
            json.dump(payload, f)
        cmd = [
            sys.executable,
            str(Path(__file__).resolve()),
            "--run-candidate-json",
            str(payload_path),
            "--candidate-result-json",
            str(result_path),
        ]
        try:
            proc = subprocess.run(
                cmd,
                text=True,
                stdout=subprocess.PIPE,
                stderr=subprocess.STDOUT,
                timeout=timeout_s if timeout_s > 0 else None,
                check=False,
            )
        except subprocess.TimeoutExpired as exc:
            output = exc.stdout or ""
            if isinstance(output, bytes):
                output = output.decode(errors="replace")
            return {
                "status": "timeout",
                "accuracy": "skipped",
                "returncode": None,
                "error": f"candidate subprocess timed out after {timeout_s}s",
                "subprocess_output": output[-4000:],
            }
        if proc.returncode != 0:
            return {
                "status": "crash",
                "accuracy": "skipped",
                "returncode": proc.returncode,
                "error": f"candidate subprocess failed with returncode={proc.returncode}",
                "subprocess_output": proc.stdout[-4000:],
            }
        if not result_path.exists():
            return {
                "status": "error",
                "accuracy": "skipped",
                "returncode": proc.returncode,
                "error": "candidate subprocess produced no result json",
                "subprocess_output": proc.stdout[-4000:],
            }
        with result_path.open() as f:
            return json.load(f)


def run_candidate_json(payload_path: str, result_path: str) -> None:
    with open(payload_path) as f:
        payload = json.load(f)
    cfg_data = payload["cfg"]
    shape = payload["shape"]
    run = payload["run"]
    torch.set_default_device("cuda")
    cfg = AiterMoeConfig(
        quant_type=cfg_data["quant_type"],
        solution_type=cfg_data["solution_type"],
        need_shuffle=bool(cfg_data["need_shuffle"]),
        need_shuffle_scale=bool(cfg_data["need_shuffle_scale"]),
        config=cfg_data["config"],
    )
    dtype = dtype_from_name(shape["dtype"])
    data = make_inputs(
        m=int(shape["m"]),
        k=int(shape["k"]),
        n=int(shape["n"]),
        e=int(shape["e"]),
        topk=int(shape["topk"]),
        dtype=dtype,
        seed=int(shape["seed"]),
    )
    row = run_one(
        data=data,
        cfg=cfg,
        warmup=int(run["warmup"]),
        iters=int(run["iters"]),
        check=bool(run["check"]),
        atol=float(run["atol"]),
        rtol=float(run["rtol"]),
        routed_scaling_factor=float(run["routed_scaling_factor"]),
    )
    row.update(flatten_config(cfg.config))
    row["status"] = "ok"
    with open(result_path, "w") as f:
        json.dump(row, f)


def cfg_to_payload(cfg: AiterMoeConfig) -> Dict[str, Any]:
    return {
        "quant_type": cfg.quant_type,
        "solution_type": cfg.solution_type,
        "need_shuffle": cfg.need_shuffle,
        "need_shuffle_scale": cfg.need_shuffle_scale,
        "config": cfg.config,
    }


def cfg_from_payload(cfg_data: Dict[str, Any]) -> AiterMoeConfig:
    return AiterMoeConfig(
        quant_type=cfg_data["quant_type"],
        solution_type=cfg_data["solution_type"],
        need_shuffle=bool(cfg_data["need_shuffle"]),
        need_shuffle_scale=bool(cfg_data["need_shuffle_scale"]),
        config=cfg_data["config"],
    )


def run_candidate_batch_json(payload_path: str, result_path: str) -> None:
    with open(payload_path) as f:
        payload = json.load(f)
    shape = payload["shape"]
    run = payload["run"]
    torch.set_default_device("cuda")
    dtype = dtype_from_name(shape["dtype"])
    data = make_inputs(
        m=int(shape["m"]),
        k=int(shape["k"]),
        n=int(shape["n"]),
        e=int(shape["e"]),
        topk=int(shape["topk"]),
        dtype=dtype,
        seed=int(shape["seed"]),
    )
    rows = []
    for item in payload["candidates"]:
        cfg = cfg_from_payload(item["cfg"])
        row = {
            "candidate": item["candidate"],
            "status": "ok",
        }
        try:
            row.update(
                run_one(
                    data=data,
                    cfg=cfg,
                    warmup=int(run["warmup"]),
                    iters=int(run["iters"]),
                    check=bool(run["check"]),
                    atol=float(run["atol"]),
                    rtol=float(run["rtol"]),
                    routed_scaling_factor=float(run["routed_scaling_factor"]),
                )
            )
            row.update(flatten_config(cfg.config))
        except Exception as exc:
            torch.cuda.synchronize()
            row.update({"status": "error", "accuracy": "skipped", "error": repr(exc)})
            row.update(flatten_config(cfg.config))
        rows.append(row)
    with open(result_path, "w") as f:
        json.dump(rows, f)


def run_candidate_batch_subprocess(
    candidates: List[Tuple[str, AiterMoeConfig]],
    m: int,
    k: int,
    n: int,
    e: int,
    topk: int,
    dtype_name: str,
    seed: int,
    warmup: int,
    iters: int,
    check: bool,
    atol: float,
    rtol: float,
    routed_scaling_factor: float,
    timeout_s: int,
) -> List[Dict[str, Any]]:
    if not candidates:
        return []
    payload = {
        "candidates": [
            {"candidate": name, "cfg": cfg_to_payload(cfg)}
            for name, cfg in candidates
        ],
        "shape": {
            "m": m,
            "k": k,
            "n": n,
            "e": e,
            "topk": topk,
            "dtype": dtype_name,
            "seed": seed,
        },
        "run": {
            "warmup": warmup,
            "iters": iters,
            "check": check,
            "atol": atol,
            "rtol": rtol,
            "routed_scaling_factor": routed_scaling_factor,
        },
    }
    with tempfile.TemporaryDirectory(prefix="w16a16_validate_") as tmpdir:
        payload_path = Path(tmpdir) / "payload.json"
        result_path = Path(tmpdir) / "result.json"
        with payload_path.open("w") as f:
            json.dump(payload, f)
        cmd = [
            sys.executable,
            str(Path(__file__).resolve()),
            "--run-candidate-batch-json",
            str(payload_path),
            "--candidate-batch-result-json",
            str(result_path),
        ]
        batch_timeout = timeout_s * max(len(candidates), 1) if timeout_s > 0 else None
        try:
            proc = subprocess.run(
                cmd,
                text=True,
                stdout=subprocess.PIPE,
                stderr=subprocess.STDOUT,
                timeout=batch_timeout,
                check=False,
            )
        except subprocess.TimeoutExpired as exc:
            if len(candidates) > 1:
                mid = len(candidates) // 2
                return run_candidate_batch_subprocess(
                    candidates[:mid], m, k, n, e, topk, dtype_name, seed,
                    warmup, iters, check, atol, rtol, routed_scaling_factor, timeout_s,
                ) + run_candidate_batch_subprocess(
                    candidates[mid:], m, k, n, e, topk, dtype_name, seed,
                    warmup, iters, check, atol, rtol, routed_scaling_factor, timeout_s,
                )
            output = exc.stdout or ""
            if isinstance(output, bytes):
                output = output.decode(errors="replace")
            name, cfg = candidates[0]
            row = {
                "candidate": name,
                "status": "timeout",
                "accuracy": "skipped",
                "error": f"candidate subprocess timed out after {timeout_s}s",
                "subprocess_output": output[-4000:],
            }
            row.update(flatten_config(cfg.config))
            return [row]
        if proc.returncode != 0 or not result_path.exists():
            if len(candidates) > 1:
                mid = len(candidates) // 2
                return run_candidate_batch_subprocess(
                    candidates[:mid], m, k, n, e, topk, dtype_name, seed,
                    warmup, iters, check, atol, rtol, routed_scaling_factor, timeout_s,
                ) + run_candidate_batch_subprocess(
                    candidates[mid:], m, k, n, e, topk, dtype_name, seed,
                    warmup, iters, check, atol, rtol, routed_scaling_factor, timeout_s,
                )
            name, cfg = candidates[0]
            row = {
                "candidate": name,
                "status": "crash",
                "accuracy": "skipped",
                "returncode": proc.returncode,
                "error": f"candidate subprocess failed with returncode={proc.returncode}",
                "subprocess_output": proc.stdout[-4000:],
            }
            row.update(flatten_config(cfg.config))
            return [row]
        with result_path.open() as f:
            return json.load(f)


def make_stage_cfg(candidate: Dict[str, int]) -> Dict[str, int]:
    return {
        "MODE": int(candidate["MODE"]),
        "BLOCK_SIZE_M": int(candidate["BLOCK_SIZE_M"]),
    }


def run_stage_one(
    data: Dict[str, torch.Tensor],
    w1_marlin: torch.Tensor,
    w2_marlin: torch.Tensor,
    candidate: Dict[str, int],
    stage: str,
    warmup: int,
    iters: int,
    align_method: str,
) -> Dict[str, Any]:
    hidden_states = data["hidden_states"]
    topk_weights = data["topk_weights"]
    topk_ids = data["topk_ids"]
    m, k = hidden_states.shape
    topk = topk_ids.shape[1]
    num_experts = w1_marlin.shape[0]
    config = make_stage_cfg(candidate)
    block_size_m = int(config["BLOCK_SIZE_M"])
    sorted_token_ids, expert_ids, num_tokens_post_pad = align_for_moe_c_method(
        align_method,
        topk_ids,
        topk_weights,
        num_experts,
        k,
        hidden_states.dtype,
        block_size_m,
    )
    sorted_token_ids_for_kernel = sorted_ids_for_moe_c_mode(
        sorted_token_ids,
        m,
        topk,
        int(config["MODE"]),
        align_method,
    )
    if stage == "gemm1":
        n = w2_marlin.shape[1] * 16
        output = torch.empty((m * topk, 2 * n), device=hidden_states.device, dtype=hidden_states.dtype)
        input_tensor = hidden_states
        weight = w1_marlin
        topk_weights_arg = None
        topk_arg = topk
    elif stage == "gemm2":
        n = w2_marlin.shape[1] * 16
        out_k = w2_marlin.shape[2] // 16
        input_tensor = torch.randn((m * topk, n), device=hidden_states.device, dtype=hidden_states.dtype) / 10
        output = torch.empty((m * topk, out_k), device=hidden_states.device, dtype=hidden_states.dtype)
        weight = w2_marlin
        topk_weights_arg = topk_weights
        topk_arg = 1 if align_method == "moe_align" else topk if int(config["MODE"]) < 400 else 1
    else:
        raise ValueError(f"unknown stage: {stage}")

    def fn() -> torch.Tensor:
        gemm_op = (
            aiter.moe_c_moe_gemm_marlin_w16a16_asm
            if int(config["MODE"]) >= 1000
            else aiter.moe_c_moe_gemm_marlin_w16a16
        )
        return gemm_op(
            input_tensor,
            weight,
            output,
            topk_weights_arg,
            sorted_token_ids_for_kernel,
            expert_ids,
            num_tokens_post_pad,
            topk_arg,
            int(config["MODE"]),
            int(config.get("DELTA", 1)),
        )

    _, us = bench_us(fn, warmup=warmup, iters=iters)
    return {
        "us": us,
        "stage_us": us,
        "num_tokens_post_pad": int(num_tokens_post_pad.item()),
        "accuracy": "unchecked",
        "status": "ok",
        "GEMM_CONFIG.BLOCK_SIZE_M": int(config["BLOCK_SIZE_M"]),
        "GEMM_CONFIG.MODE": int(config["MODE"]),
    }


def run_stage_batch_json(payload_path: str, result_path: str) -> None:
    with open(payload_path) as f:
        payload = json.load(f)
    shape = payload["shape"]
    run = payload["run"]
    torch.set_default_device("cuda")
    dtype = dtype_from_name(shape["dtype"])
    data = make_inputs(
        m=int(shape["m"]),
        k=int(shape["k"]),
        n=int(shape["n"]),
        e=int(shape["e"]),
        topk=int(shape["topk"]),
        dtype=dtype,
        seed=int(shape["seed"]),
    )
    w1_marlin = torch.stack([w16a16_marlin_weight(data["w1"][i]) for i in range(int(shape["e"]))])
    w2_marlin = torch.stack([w16a16_marlin_weight(data["w2"][i]) for i in range(int(shape["e"]))])
    rows = []
    for candidate in payload["candidates"]:
        row = {
            "candidate": stage_candidate_name(candidate),
            "stage": payload["stage"],
            "status": "ok",
        }
        try:
            row.update(
                run_stage_one(
                    data=data,
                    w1_marlin=w1_marlin,
                    w2_marlin=w2_marlin,
                    candidate=candidate,
                    stage=payload["stage"],
                    warmup=int(run["warmup"]),
                    iters=int(run["iters"]),
                    align_method=run["align_method"],
                )
            )
        except Exception as exc:
            torch.cuda.synchronize()
            row.update({"status": "error", "accuracy": "skipped", "error": repr(exc)})
            row.update(flatten_stage_candidate(candidate))
        rows.append(row)
    with open(result_path, "w") as f:
        json.dump(rows, f)


def stage_candidate_name(candidate: Dict[str, int]) -> str:
    return (
        f"{candidate['MODE']}:"
        f"{candidate['BLOCK_SIZE_M']}"
    )


def flatten_stage_candidate(candidate: Dict[str, int]) -> Dict[str, int]:
    return {
        "GEMM_CONFIG.MODE": int(candidate["MODE"]),
        "GEMM_CONFIG.BLOCK_SIZE_M": int(candidate["BLOCK_SIZE_M"]),
    }


def best_stage_rows_by_bm(
    stage_rows: List[Dict[str, Any]],
    limit_per_bm: int,
) -> Dict[int, List[Dict[str, Any]]]:
    rows_by_bm: Dict[int, List[Dict[str, Any]]] = {}
    for row in stage_rows:
        if row.get("status") != "ok":
            continue
        bm = int(row["GEMM_CONFIG.BLOCK_SIZE_M"])
        rows_by_bm.setdefault(bm, []).append(row)
    for bm, rows in rows_by_bm.items():
        rows.sort(key=lambda row: float(row["stage_us"]))
        rows_by_bm[bm] = rows[:limit_per_bm]
    return rows_by_bm


def run_stage_batch_subprocess(
    stage: str,
    candidates: List[Dict[str, int]],
    m: int,
    k: int,
    n: int,
    e: int,
    topk: int,
    dtype_name: str,
    seed: int,
    warmup: int,
    iters: int,
    align_method: str,
    timeout_s: int,
) -> List[Dict[str, Any]]:
    if not candidates:
        return []
    payload = {
        "stage": stage,
        "candidates": candidates,
        "shape": {
            "m": m,
            "k": k,
            "n": n,
            "e": e,
            "topk": topk,
            "dtype": dtype_name,
            "seed": seed,
        },
        "run": {
            "warmup": warmup,
            "iters": iters,
            "align_method": align_method,
        },
    }
    with tempfile.TemporaryDirectory(prefix="w16a16_stage_tune_") as tmpdir:
        payload_path = Path(tmpdir) / "payload.json"
        result_path = Path(tmpdir) / "result.json"
        with payload_path.open("w") as f:
            json.dump(payload, f)
        cmd = [
            sys.executable,
            str(Path(__file__).resolve()),
            "--run-stage-batch-json",
            str(payload_path),
            "--stage-batch-result-json",
            str(result_path),
        ]
        batch_timeout = timeout_s * max(len(candidates), 1) if timeout_s > 0 else None
        try:
            proc = subprocess.run(
                cmd,
                text=True,
                stdout=subprocess.PIPE,
                stderr=subprocess.STDOUT,
                timeout=batch_timeout,
                check=False,
            )
        except subprocess.TimeoutExpired as exc:
            if len(candidates) > 1:
                mid = len(candidates) // 2
                return run_stage_batch_subprocess(
                    stage, candidates[:mid], m, k, n, e, topk, dtype_name,
                    seed, warmup, iters, align_method, timeout_s,
                ) + run_stage_batch_subprocess(
                    stage, candidates[mid:], m, k, n, e, topk, dtype_name,
                    seed, warmup, iters, align_method, timeout_s,
                )
            output = exc.stdout or ""
            if isinstance(output, bytes):
                output = output.decode(errors="replace")
            row = {
                "candidate": stage_candidate_name(candidates[0]),
                "stage": stage,
                "status": "timeout",
                "accuracy": "skipped",
                "error": f"candidate subprocess timed out after {timeout_s}s",
                "subprocess_output": output[-4000:],
            }
            row.update(flatten_stage_candidate(candidates[0]))
            return [row]
        if proc.returncode != 0 or not result_path.exists():
            if len(candidates) > 1:
                mid = len(candidates) // 2
                return run_stage_batch_subprocess(
                    stage, candidates[:mid], m, k, n, e, topk, dtype_name,
                    seed, warmup, iters, align_method, timeout_s,
                ) + run_stage_batch_subprocess(
                    stage, candidates[mid:], m, k, n, e, topk, dtype_name,
                    seed, warmup, iters, align_method, timeout_s,
                )
            row = {
                "candidate": stage_candidate_name(candidates[0]),
                "stage": stage,
                "status": "crash",
                "accuracy": "skipped",
                "returncode": proc.returncode,
                "error": f"candidate subprocess failed with returncode={proc.returncode}",
                "subprocess_output": proc.stdout[-4000:],
            }
            row.update(flatten_stage_candidate(candidates[0]))
            return [row]
        with result_path.open() as f:
            return json.load(f)


def flatten_config(config: Optional[Dict[str, Any]]) -> Dict[str, Any]:
    out: Dict[str, Any] = {}
    if not config:
        return out
    for key, value in config.items():
        if isinstance(value, dict):
            for sub_key, sub_value in value.items():
                out[f"{key}.{sub_key}"] = sub_value
        else:
            out[key] = value
    return out


def config_root(arch: str) -> Path:
    return Path(__file__).resolve().parents[1] / "aiter" / "moe_c_configs" / arch / "w16a16"


def marlin_config_file_name(
    e: int,
    n: int,
    k: int,
) -> str:
    return f"E={e},N={n},K={k},dtype=w16a16.json"


def load_json_config(path: Path) -> Dict[str, Dict[str, int]]:
    if not path.exists():
        return {}
    with path.open() as f:
        return json.load(f)


def ordered_token_config(config: Dict[str, Dict[str, int]]) -> Dict[str, Dict[str, int]]:
    return {str(key): config[str(key)] for key in sorted((int(k) for k in config.keys()))}


def write_best_moe_c_configs(
    best_rows: List[Dict[str, Any]],
    arch: str,
    e: int,
    inter_dim: int,
    model_dim: int,
) -> Tuple[Path, Path]:
    root = config_root(arch)
    root.mkdir(parents=True, exist_ok=True)

    gemm1_path = root / marlin_config_file_name(e, 2 * inter_dim, model_dim)
    gemm2_path = root / marlin_config_file_name(e, model_dim, inter_dim)
    gemm1_config = load_json_config(gemm1_path)
    gemm2_config = load_json_config(gemm2_path)

    for row in best_rows:
        token = str(int(row["m"]))
        gemm1_config[token] = {
            "BLOCK_SIZE_M": int(row["GEMM1_CONFIG.BLOCK_SIZE_M"]),
            "MODE": int(row["GEMM1_CONFIG.MODE"]),
        }
        gemm2_config[token] = {
            "BLOCK_SIZE_M": int(row["GEMM2_CONFIG.BLOCK_SIZE_M"]),
            "MODE": int(row["GEMM2_CONFIG.MODE"]),
        }

    with gemm1_path.open("w") as f:
        json.dump(ordered_token_config(gemm1_config), f, indent=4)
        f.write("\n")
    with gemm2_path.open("w") as f:
        json.dump(ordered_token_config(gemm2_config), f, indent=4)
        f.write("\n")
    return gemm1_path, gemm2_path


def build_arg_parser() -> argparse.ArgumentParser:
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument("--run-candidate-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--candidate-result-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--run-candidate-batch-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--candidate-batch-result-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--run-stage-batch-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--stage-batch-result-json", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--m-list", default=DEFAULT_M_LIST)
    parser.add_argument("--k", type=int, default=DEFAULT_MODEL_DIM, help="model dimension")
    parser.add_argument("--n", type=int, default=DEFAULT_INTER_DIM, help="MOE intermediate dimension")
    parser.add_argument("--e", type=int, default=DEFAULT_NUM_EXPERTS, help="number of experts")
    parser.add_argument("--topk", type=int, default=DEFAULT_TOPK)
    parser.add_argument("--dtype", default="bf16", choices=("bf16", "fp16", "bfloat16", "float16"))
    parser.add_argument("--use-shuffle", type=int, default=1)
    parser.add_argument(
        "--moe-c-candidates",
        default=None,
        help="Comma list: MODE1:MODE2[:BM1[:BM2]]. BM is derived from mode when omitted.",
    )
    parser.add_argument(
        "--mode-preset",
        default="auto",
        choices=("auto", "all", "decode", "prefill"),
        help=(
            "Mode preset used when --mode1-list/--mode2-list are not overridden. "
            "auto uses all modes whose BLOCK_SIZE_M is smaller than M, with a smallest-BM fallback."
        ),
    )
    parser.add_argument(
        "--decode-threshold",
        type=int,
        default=W16A16_MOE_C_DECODE_THRESHOLD,
        help="Compatibility option; auto mode now filters candidates by M > BLOCK_SIZE_M.",
    )
    parser.add_argument("--mode1-list", default=None)
    parser.add_argument("--mode2-list", default=None)
    parser.add_argument("--bm1-list", default=None, help=argparse.SUPPRESS)
    parser.add_argument("--bm2-list", default=None, help=argparse.SUPPRESS)
    parser.add_argument(
        "--include-current",
        action="store_true",
        help="Also test the current config from get_aiter_moe_config. This requires existing config files.",
    )
    parser.add_argument("--warmup", type=int, default=10)
    parser.add_argument("--iters", type=int, default=100)
    parser.add_argument("--stage-batch-size", type=int, default=64)
    parser.add_argument("--top-stage-candidates", type=int, default=8)
    parser.add_argument(
        "--max-validation-candidates",
        type=int,
        default=256,
        help="Validate only the fastest stage-estimated GEMM1/GEMM2 pairs; <=0 means no cap.",
    )
    parser.add_argument(
        "--same-bm-only",
        action="store_true",
        help="Only validate GEMM1/GEMM2 pairs with identical BLOCK_SIZE_M.",
    )
    parser.add_argument("--validate-warmup", type=int, default=10)
    parser.add_argument("--validate-iters", type=int, default=100)
    parser.add_argument("--moe-c-align", choices=("ck", "moe_align"), default="ck")
    parser.add_argument(
        "--no-isolate-candidates",
        action="store_true",
        help="Run candidates in the main process. Faster, but native crashes stop the whole tune.",
    )
    parser.add_argument("--candidate-timeout-s", type=int, default=180)
    parser.add_argument("--seed", type=int, default=0)
    parser.add_argument("--no-check", action="store_true")
    parser.add_argument("--atol", type=float, default=0.5)
    parser.add_argument("--rtol", type=float, default=0.01)
    parser.add_argument("--routed-scaling-factor", type=float, default=1.0)
    parser.add_argument("--output", default="w16a16_tune_config_detail.csv")
    parser.add_argument("--best-output", default="w16a16_tune_config_best.csv")
    parser.add_argument("--write-configs", action="store_true", help="Merge best configs into aiter/moe_c_configs/<arch>/w16a16")
    parser.add_argument("--arch", default=None, help="Override output arch directory, e.g. gfx936")
    return parser


def main() -> None:
    args = build_arg_parser().parse_args()
    if args.run_candidate_json:
        run_candidate_json(args.run_candidate_json, args.candidate_result_json)
        return
    if args.run_candidate_batch_json:
        run_candidate_batch_json(args.run_candidate_batch_json, args.candidate_batch_result_json)
        return
    if args.run_stage_batch_json:
        run_stage_batch_json(args.run_stage_batch_json, args.stage_batch_result_json)
        return

    torch.set_default_device("cuda")
    dtype = dtype_from_name(args.dtype)
    m_list = parse_int_list(args.m_list)
    if args.moe_c_candidates:
        explicit_candidates = parse_moe_c_candidates(args.moe_c_candidates)
        make_candidates = lambda m: iter(explicit_candidates)

        def make_stage_candidates(m: int, stage: str) -> List[Dict[str, int]]:
            unique = {}
            for cand in explicit_candidates:
                if stage == "gemm1":
                    candidate = make_stage_cfg(
                        {"MODE": cand["MODE1"], "BLOCK_SIZE_M": cand["BM1"]}
                    )
                elif stage == "gemm2":
                    candidate = make_stage_cfg(
                        {"MODE": cand["MODE2"], "BLOCK_SIZE_M": cand["BM2"]}
                    )
                else:
                    raise ValueError(f"unknown stage: {stage}")
                unique[stage_candidate_name(candidate)] = candidate
            return list(unique.values())
    else:
        def make_candidates(m: int) -> Iterable[Dict[str, int]]:
            preset_modes = modes_for_preset(args.mode_preset, m, args.decode_threshold)
            mode1_list = parse_int_list(args.mode1_list) if args.mode1_list else preset_modes
            mode2_list = parse_int_list(args.mode2_list) if args.mode2_list else preset_modes
            return make_moe_c_candidate_grid(
                mode1_list=mode1_list,
                mode2_list=mode2_list,
            )

        def make_stage_candidates(m: int, stage: str) -> List[Dict[str, int]]:
            preset_modes = modes_for_preset(args.mode_preset, m, args.decode_threshold)
            if stage == "gemm1":
                mode_list = parse_int_list(args.mode1_list) if args.mode1_list else preset_modes
            elif stage == "gemm2":
                mode_list = parse_int_list(args.mode2_list) if args.mode2_list else preset_modes
            else:
                raise ValueError(f"unknown stage: {stage}")
            candidates = list(make_stage_candidate_grid(mode_list))
            unique = {}
            for candidate in candidates:
                unique[stage_candidate_name(candidate)] = candidate
            return list(unique.values())
    arch = args.arch or current_arch()

    rows: List[Dict[str, Any]] = []
    best_rows: List[Dict[str, Any]] = []
    for m in m_list:
        gemm1_candidates = make_stage_candidates(m, "gemm1")
        gemm2_candidates = make_stage_candidates(m, "gemm2")
        print(
            f"[w16a16_tune] m={m}, gemm1_candidates={len(gemm1_candidates)}, "
            f"gemm2_candidates={len(gemm2_candidates)}, "
            f"align={args.moe_c_align}",
            flush=True,
        )

        stage_rows: Dict[str, List[Dict[str, Any]]] = {}
        for stage in ("gemm1", "gemm2"):
            stage_candidates = gemm1_candidates if stage == "gemm1" else gemm2_candidates
            stage_rows[stage] = []
            for begin in range(0, len(stage_candidates), args.stage_batch_size):
                batch = stage_candidates[begin: begin + args.stage_batch_size]
                batch_rows = run_stage_batch_subprocess(
                    stage=stage,
                    candidates=batch,
                    m=m,
                    k=args.k,
                    n=args.n,
                    e=args.e,
                    topk=args.topk,
                    dtype_name=args.dtype,
                    seed=args.seed,
                    warmup=args.warmup,
                    iters=args.iters,
                    align_method=args.moe_c_align,
                    timeout_s=args.candidate_timeout_s,
                )
                for row in batch_rows:
                    row.update(
                        {
                            "m": m,
                            "k": args.k,
                            "n": args.n,
                            "e": args.e,
                            "topk": args.topk,
                            "dtype": dtype_to_config_name(dtype),
                            "solution": MoeSolutionType.MOE_C,
                        }
                    )
                    rows.append(row)
                    stage_rows[stage].append(row)
                print(
                    f"[w16a16_tune] m={m} {stage} batch "
                    f"{begin // args.stage_batch_size + 1}/"
                    f"{(len(stage_candidates) + args.stage_batch_size - 1) // args.stage_batch_size} done",
                    flush=True,
                )

        top_rows_by_bm = {
            "gemm1": best_stage_rows_by_bm(stage_rows["gemm1"], args.top_stage_candidates),
            "gemm2": best_stage_rows_by_bm(stage_rows["gemm2"], args.top_stage_candidates),
        }
        base_cfg = make_empty_moe_c_config()
        validation_rows: List[Dict[str, Any]] = []
        validation_candidates: List[Tuple[str, AiterMoeConfig]] = []
        stage_times: Dict[str, Tuple[float, float]] = {}
        gemm1_top_rows = [row for rows_by_bm in top_rows_by_bm["gemm1"].values() for row in rows_by_bm]
        gemm2_top_rows = [row for rows_by_bm in top_rows_by_bm["gemm2"].values() for row in rows_by_bm]
        candidate_pairs: List[Tuple[float, Dict[str, Any], Dict[str, Any]]] = []
        for gemm1_row in gemm1_top_rows:
            bm1 = int(gemm1_row["GEMM_CONFIG.BLOCK_SIZE_M"])
            for gemm2_row in gemm2_top_rows:
                bm2 = int(gemm2_row["GEMM_CONFIG.BLOCK_SIZE_M"])
                if args.same_bm_only and bm1 != bm2:
                    continue
                if bm1 < bm2:
                    continue
                if not pair_is_single_sort_compatible(bm1, bm2):
                    continue
                candidate_pairs.append(
                    (
                        float(gemm1_row["stage_us"]) + float(gemm2_row["stage_us"]),
                        gemm1_row,
                        gemm2_row,
                    )
                )
        candidate_pairs.sort(key=lambda item: item[0])
        if args.max_validation_candidates > 0:
            candidate_pairs = candidate_pairs[: args.max_validation_candidates]
        if not candidate_pairs:
            print(f"[w16a16_tune] m={m} no stage candidates to validate", flush=True)
            continue

        seen_validation_candidates = set()
        for _, gemm1_row, gemm2_row in candidate_pairs:
            bm1 = int(gemm1_row["GEMM_CONFIG.BLOCK_SIZE_M"])
            bm2 = int(gemm2_row["GEMM_CONFIG.BLOCK_SIZE_M"])
            cfg = copy.deepcopy(base_cfg)
            cfg.config = make_pair_config(
                int(gemm1_row["GEMM_CONFIG.MODE"]),
                bm1,
                int(gemm2_row["GEMM_CONFIG.MODE"]),
                bm2,
            )
            candidate_name = config_name(cfg)
            if candidate_name in seen_validation_candidates:
                continue
            seen_validation_candidates.add(candidate_name)
            validation_candidates.append((candidate_name, cfg))
            stage_times[candidate_name] = (
                float(gemm1_row["stage_us"]),
                float(gemm2_row["stage_us"]),
            )
        print(
            f"[w16a16_tune] m={m} validating {len(validation_candidates)} "
            f"candidate pairs (same_bm_only={args.same_bm_only})",
            flush=True,
        )

        validation_results = run_candidate_batch_subprocess(
            candidates=validation_candidates,
            m=m,
            k=args.k,
            n=args.n,
            e=args.e,
            topk=args.topk,
            dtype_name=args.dtype,
            seed=args.seed,
            warmup=args.validate_warmup,
            iters=args.validate_iters,
            check=not args.no_check,
            atol=args.atol,
            rtol=args.rtol,
            routed_scaling_factor=args.routed_scaling_factor,
            timeout_s=args.candidate_timeout_s,
        )
        for result in validation_results:
            candidate_name = result["candidate"]
            gemm1_stage_us, gemm2_stage_us = stage_times.get(candidate_name, (None, None))
            validation_row = {
                    "m": m,
                    "k": args.k,
                    "n": args.n,
                    "e": args.e,
                    "topk": args.topk,
                    "dtype": dtype_to_config_name(dtype),
                    "solution": MoeSolutionType.MOE_C,
                    "stage": "e2e_validate",
                    "candidate": candidate_name,
                    "need_shuffle": base_cfg.need_shuffle,
                    "gemm1_stage_us": gemm1_stage_us,
                    "gemm2_stage_us": gemm2_stage_us,
                    "status": result.get("status", "ok"),
            }
            validation_row.update(result)
            rows.append(validation_row)
            validation_rows.append(validation_row)
            print(f"[w16a16_tune] validate result: {validation_row}", flush=True)

        ok_validation = [
            row for row in validation_rows
            if row.get("status") == "ok"
            and (args.no_check or row.get("accuracy") == "passed")
        ]
        if not ok_validation:
            print(f"[w16a16_tune] m={m} no passing validated candidate", flush=True)
            continue
        best = min(ok_validation, key=lambda row: float(row["us"]))
        best_rows.append(best)
        print(f"[w16a16_tune] m={m} best={best}", flush=True)

    df = pd.DataFrame(rows)
    print(df)
    df.to_csv(args.output, index=False)
    print(f"[w16a16_tune] detail csv saved to {args.output}")

    ok = pd.DataFrame(best_rows)
    required_config_cols = [
        "GEMM1_CONFIG.BLOCK_SIZE_M",
        "GEMM1_CONFIG.MODE",
        "GEMM1_CONFIG.DELTA",
        "GEMM2_CONFIG.BLOCK_SIZE_M",
        "GEMM2_CONFIG.MODE",
        "GEMM2_CONFIG.DELTA",
    ]
    if not ok.empty:
        ok = ok.dropna(subset=required_config_cols)
    if ok.empty:
        print("[w16a16_tune] no passing rows")
        return

    best = ok.sort_values("m")
    best.to_csv(args.best_output, index=False)
    print(f"[w16a16_tune] best csv saved to {args.best_output}")

    if args.write_configs:
        gemm1_path, gemm2_path = write_best_moe_c_configs(
            best_rows=best.to_dict("records"),
            arch=arch,
            e=args.e,
            inter_dim=args.n,
            model_dim=args.k,
        )
        print(f"[w16a16_tune] GEMM1 config written to {gemm1_path}")
        print(f"[w16a16_tune] GEMM2 config written to {gemm2_path}")


if __name__ == "__main__":
    main()
