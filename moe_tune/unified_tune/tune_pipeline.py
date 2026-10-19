# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""编排调优、独立验证与可选配置安装。

启动隔离 worker，控制超时/中断、日志、状态与断点续跑；
双后端分别记录结果，并对成功产物执行校验和安装。"""
import json
import os
from pathlib import Path
import signal
import subprocess
import sys
import time
import uuid

from . import route_table
from .tune_artifacts import exclusive_lock, install, resume_valid, validate_files, write_json
from .tune_spec import digest, log_shape_progress

WORKER = Path(__file__).with_name("tune_worker.py")
ROOT = WORKER.parents[2]
_INDTYPE = {"fp16": "torch.float16", "bf16": "torch.bfloat16"}


def _resume_ok(args, backend, previous, fingerprint):
    """moe_c emits no artifact files (resume_valid needs hashes), but its
    timing manifest alone is a legitimate resume point (4.3)."""
    if not args.resume:
        return False
    if previous.get("fingerprint") != fingerprint:
        return False
    if backend == "moe_c":
        return previous.get("status") in ("validated", "installed")
    return resume_valid(previous, fingerprint)


def _tuned_tokens(manifest, backend):
    """Tokens this backend tuned successfully."""
    tuning = (manifest or {}).get("tuning") or {}
    if backend == "asm":
        return {int(c["token"]) for c in tuning.get("cases", [])
                if (c.get("best") or {}).get("median_us")}
    if backend == "triton":
        return {int(c["token"]) for c in tuning.get("cases", []) if c.get("gemm_sum_ms")}
    return {int(token) for token in (tuning.get("timings") or {})}


def _token_timings(manifest, backend):
    """Per-token timings (us) that are comparable across backends: the CUDA graph
    median of the full public call, measured during validation. Tuning-time
    numbers are not used because they cover different work per backend (for
    example, triton's autotune time is the sum of its two GEMMs only). Tokens that
    were not tuned or have no validation timing are left out."""
    validation = (manifest or {}).get("validation") or {}
    measured = {}
    for case in validation.get("cases", []):
        median = (case.get("graph_end_to_end") or {}).get("median_us")
        if median:
            measured[int(case["token"])] = float(median)
    return {t: measured[t] for t in _tuned_tokens(manifest, backend) if t in measured}


def _forward_shape_progress(stream):
    """跟读完整进度行；原生调优诊断保留在日志文件，不刷满控制台。"""
    while True:
        position = stream.tell()
        line = stream.readline()
        if not line:
            return
        if not line.endswith("\n"):
            stream.seek(position)
            return
        if line.startswith(("[shape ", "M=")):
            print(line, end="", flush=True)


def execute_worker(request, request_path, result_path, log_path, timeout):
    write_json(request_path, request)
    result_path.unlink(missing_ok=True)
    command = [sys.executable, "-I", "-B", str(WORKER), "--request", str(request_path), "--result", str(result_path)]
    environment = os.environ.copy()
    environment.update(PYTHONUNBUFFERED="1", PYTHONDONTWRITEBYTECODE="1", PYTHONUTF8="1")
    # Inherited training flags must not leak into probe/validation processes.
    for key in ("TRAINING_MODE", "TRITON_COMPILE_ONLY", "AUTOTUNE_TEST_TYPE", "CUR_GROUP", "EP_SIZE",
                "NUM_GROUPS_COMPILE", "SPLITK_SIZE"):
        environment.pop(key, None)
    # The input contract is one native inference chunk, independent of caller overrides.
    environment["TRITON_FUSED_MOE_CHUNK_SIZE"] = "32768"
    with log_path.open("w", encoding="utf-8") as log:
        log.write(json.dumps(dict(command=command, request=request), sort_keys=True) + "\n"); log.flush()
        child = subprocess.Popen(command, cwd=ROOT, env=environment, stdout=log, stderr=subprocess.STDOUT,
                                 start_new_session=(os.name != "nt"))
        with log_path.open("r", encoding="utf-8", errors="replace") as progress_log:
            deadline = time.monotonic() + timeout
            try:
                while True:
                    _forward_shape_progress(progress_log)
                    remaining = deadline - time.monotonic()
                    if remaining <= 0:
                        raise subprocess.TimeoutExpired(command, timeout)
                    try:
                        child.wait(timeout=min(0.2, remaining))
                        break
                    except subprocess.TimeoutExpired:
                        continue
            except BaseException as exc:
                if child.poll() is None:
                    if os.name == "nt": child.terminate()
                    else: os.killpg(child.pid, signal.SIGTERM)
                    try: child.wait(timeout=10)
                    except subprocess.TimeoutExpired:
                        if os.name == "nt": child.kill()
                        else: os.killpg(child.pid, signal.SIGKILL)
                        child.wait()
                if isinstance(exc, subprocess.TimeoutExpired):
                    raise RuntimeError(f"{request['action']} timed out after {timeout}s; log: {log_path}") from exc
                raise
            finally:
                _forward_shape_progress(progress_log)
    result = json.loads(result_path.read_text(encoding="utf-8")) if result_path.exists() else {}
    expected_status = {"probe": "passed", "tune": "tuned", "validate": "passed",
                       "verify_install": "passed"}[request['action']]
    if child.returncode or result.get("status") != expected_status:
        raise RuntimeError(f"{request['action']} failed ({child.returncode}): {result.get('error', 'no result')}; log: {log_path}")
    return result


def _write_route_table(root, specs, runtime, backends, manifests, *, args, failures):
    """route mode (moe_c in backends): per spec & token pick the
    fastest eligible backend, emit tuned_fused_moe_route.csv under the run
    dir and (with --install-configs) merge-install into route_config_dir.
    All backends are compared on the validation-time CUDA graph median of the
    full public call (see _token_timings)."""
    if "moe_c" not in backends:
        return None
    rows = []
    for spec in specs:
        per = {b: _token_timings(manifests.get((spec.case_id, b)), b) for b in backends}
        tokens = sorted(set().union(*[set(v) for v in per.values() if v]) if any(per.values()) else [])
        for token in tokens:
            cand = sorted((us, b) for b, m in per.items() for t, us in m.items() if t == token)
            if not cand:
                continue
            us, backend = cand[0]
            rows.append(dict(arch=runtime["arch"], quant_type=spec.quant_type,
                             indtype=_INDTYPE[spec.dtype], inter_dim=spec.inter_dim,
                             model_dim=spec.model_dim, expert=spec.experts, topk=spec.topk,
                             q_size_n=spec.q_size_n, q_size_k=spec.q_size_k,
                             token=token, backend=backend, time_us=round(us, 3)))
    out_dir = root / "route"
    out_dir.mkdir(parents=True, exist_ok=True)
    target = out_dir / route_table.ROUTE_FILENAME
    target.write_bytes(route_table.merge_route_csv(
        target.read_bytes() if target.exists() else None, route_table.write_route_csv(rows)))
    installed = None
    if args.install_configs and rows:
        installed = route_table.install_route([target], runtime)
    return dict(file=str(target), rows=len(rows), installed=bool(installed),
                eligible_backends=backends)


def run(args, specs, backends):
    root = args.output_dir.resolve(); root.mkdir(parents=True, exist_ok=True)
    options = {k: getattr(args, k) for k in ("device", "search", "warmup", "iterations")}
    probe_dir = root / ".runs" / uuid.uuid4().hex; probe_dir.mkdir(parents=True)
    print(f"Checking runtime on logical GPU {args.device} ...", flush=True)
    probe = execute_worker(dict(action="probe", options=options), probe_dir / "probe_request.json",
                           probe_dir / "probe.json", probe_dir / "probe.log", args.timeout)
    runtime = probe["runtime"]
    failures = []
    manifests = {}
    shape_total = sum(len(spec.tokens) for spec in specs)
    shape_offset = 0
    for spec in specs:
        case_dir = root / runtime["arch"] / spec.case_id
        case_dir.mkdir(parents=True, exist_ok=True)
        with exclusive_lock(case_dir / ".lock"):
            for backend_index, backend in enumerate(backends, start=1):
                progress = dict(shape_offset=shape_offset, shape_total=shape_total,
                                backend_index=backend_index, backend_total=len(backends))
                directory = case_dir / backend
                directory.mkdir(parents=True, exist_ok=True)
                manifest_path = directory / "manifest.json"
                # Device load/free memory and timings do not participate in the identity.
                fingerprint = digest(dict(spec=spec.to_dict(), backend=backend, options=options, runtime=runtime))
                previous = json.loads(manifest_path.read_text()) if manifest_path.exists() else {}
                manifest = dict(fingerprint=fingerprint, spec=spec.to_dict(), backend=backend,
                                options=options, runtime=runtime, status="pending")
                try:
                    if _resume_ok(args, backend, previous, fingerprint):
                        manifest = previous
                        files = list(manifest["artifact_hashes"])
                        for m in spec.tokens:
                            log_shape_progress(spec, m, backend, progress, stage="RESUME")
                        print(f"RESUME {backend} {spec.case_id}: verified artifacts", flush=True)
                    else:
                        if previous and not args.resume:
                            raise ValueError(f"{manifest_path} already exists; use --resume or a new --output-dir")
                        write_json(manifest_path, manifest)
                        request = dict(spec=spec.to_dict(), backend=backend, options=options,
                                       workdir=str(directory), progress=progress)
                        started = time.monotonic()
                        print(f"TUNE {backend} {spec.case_id}, tokens={spec.tokens}, search={args.search}", flush=True)
                        tuned = execute_worker(dict(request, action="tune"), directory / "tune_request.json",
                            directory / "tune_result.json", directory / "tune.log", args.timeout)
                        files = tuned["files"]
                        hashes = ({} if backend == "moe_c"
                                  else validate_files(spec, backend, files, runtime["arch"]))
                        validate_request = dict(request, action="validate")
                        if "moe_c" in backends:
                            validate_request["options"] = dict(request["options"],
                                                                fused_moe_readback=True)
                        validation = execute_worker(validate_request, directory / "validate_request.json",
                            directory / "validation.json", directory / "validation.log", args.timeout)
                        manifest.update(status="validated", artifact_hashes=hashes, tuning=tuned,
                                        validation=validation, wall_seconds=time.monotonic() - started)
                        write_json(manifest_path, manifest)
                    if args.install_configs and backend != "moe_c":
                        validate_files(spec, backend, files, runtime["arch"])
                        manifest["status"] = "validated"
                        manifest.pop("installation_error", None)
                        manifest.pop("installation_validation", None)
                        manifest["installation"] = install(spec, backend, files, runtime,
                            replace_existing=args.replace_existing_configs)
                        write_json(manifest_path, manifest)
                        if backend == "triton":
                            check_request = dict(action="verify_install", spec=spec.to_dict(), backend=backend,
                                                 options=options, workdir=str(directory))
                            manifest["installation_validation"] = execute_worker(check_request,
                                directory / "install_check_request.json", directory / "install_check.json",
                                directory / "install_check.log", args.timeout)
                        manifest["status"] = "installed"
                        write_json(manifest_path, manifest)
                    manifests[(spec.case_id, backend)] = manifest
                    print(f"PASS {backend}: {manifest_path}", flush=True)
                except (Exception, KeyboardInterrupt) as exc:
                    if manifest.get("status") in ("validated", "installed"):
                        manifest["installation_error"] = str(exc)
                    else:
                        manifest.update(status="interrupted" if isinstance(exc, KeyboardInterrupt) else "failed", error=str(exc))
                    # Do not replace a prior successful manifest when the user omitted --resume.
                    if not previous or args.resume:
                        write_json(manifest_path, manifest)
                    failures.append(dict(case_id=spec.case_id, backend=backend, error=str(exc)))
                    print(f"FAIL {backend}: {exc}", file=sys.stderr, flush=True)
                    if isinstance(exc, KeyboardInterrupt): raise
        shape_offset += len(spec.tokens)
    route_summary = _write_route_table(root, specs, runtime, backends, manifests,
                                       args=args, failures=failures)
    write_json(probe_dir / "run_result.json", dict(status="failed" if failures else "passed", failures=failures,
                                                  output_dir=str(root), backends=backends,
                                                  route=route_summary))
    return 1 if failures else 0
