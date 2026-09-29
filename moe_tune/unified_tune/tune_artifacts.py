# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""校验、合并与安全安装原生调优产物。

管理 CSV/双 JSON、文件哈希、目录锁、配置契约冲突和断点续跑校验；
通过备份与可恢复事务处理安装失败，保留已有无关配置。"""
import contextlib
import csv
import hashlib
import io
import json
import math
import os
from pathlib import Path
import shutil
import uuid


def file_hash(path):
    return hashlib.sha256(Path(path).read_bytes()).hexdigest()


def atomic_write(path, data):
    path = Path(path)
    path.parent.mkdir(parents=True, exist_ok=True)
    temporary = path.with_name(path.name + ".tmp-" + uuid.uuid4().hex)
    try:
        with temporary.open("wb") as stream:
            stream.write(data); stream.flush(); os.fsync(stream.fileno())
        if path.exists():
            shutil.copymode(path, temporary)
        os.replace(temporary, path)
    finally:
        temporary.unlink(missing_ok=True)


def write_json(path, data):
    atomic_write(path, json.dumps(data, indent=2, sort_keys=True, allow_nan=False).encode("utf-8"))


@contextlib.contextmanager
def exclusive_lock(path):
    """OS releases the advisory lock even if the worker is killed."""
    path = Path(path); path.parent.mkdir(parents=True, exist_ok=True)
    with path.open("a+b") as stream:
        if path.stat().st_size == 0:
            stream.write(b"0"); stream.flush()
        stream.seek(0)
        try:
            if os.name == "nt":
                import msvcrt
                msvcrt.locking(stream.fileno(), msvcrt.LK_NBLCK, 1)
            else:
                import fcntl
                fcntl.flock(stream.fileno(), fcntl.LOCK_EX | fcntl.LOCK_NB)
        except OSError as exc:
            raise RuntimeError(f"another tuning/install process holds {path}") from exc
        try:
            yield
        finally:
            stream.seek(0)
            if os.name == "nt":
                msvcrt.locking(stream.fileno(), msvcrt.LK_UNLCK, 1)
            else:
                fcntl.flock(stream.fileno(), fcntl.LOCK_UN)


def validate_files(spec, backend, files, arch):
    if len(files) != (1 if backend == "asm" else 2):
        raise ValueError("backend produced the wrong number of files")
    if backend == "asm":
        with open(files[0], newline="", encoding="utf-8") as stream:
            rows = list(csv.DictReader(stream))
        if len(rows) != len(spec.tokens) or {int(r["token"]) for r in rows} != set(spec.tokens):
            raise ValueError("ASM CSV missing/duplicate requested tokens")
        for row in rows:
            if (row["arch"] != arch or row["quant_type"] != spec.quant_type or row["sol_type"] != "asm"
                    or int(row["inter_dim"]) != spec.inter_dim or int(row["model_dim"]) != spec.model_dim
                    or int(row["expert"]) != spec.experts or int(row["topk"]) != spec.topk
                    or row["indtype"] != ("torch.float16" if spec.dtype == "fp16" else "torch.bfloat16")
                    or int(row["q_size_n"]) != spec.q_size_n or int(row["q_size_k"]) != spec.q_size_k):
                raise ValueError("ASM output does not match requested shape/type")
            ids = row["sol_id"].split("+")
            if len(ids) != 2 or not all(x.isdigit() for x in ids):
                raise ValueError("invalid ASM solution ID")
            if not math.isfinite(float(row["time_us"])) or float(row["time_us"]) <= 0:
                raise ValueError("ASM output has invalid timing")
    else:
        pair = [json.loads(Path(p).read_text(encoding="utf-8")) for p in files]
        expected = set(map(str, spec.tokens))
        for data in pair:
            if not isinstance(data, dict) or set(data) != expected:
                raise ValueError("Triton JSON missing/extra/duplicate requested token result")
            for config in data.values():
                for key in ("BLOCK_SIZE_M", "BLOCK_SIZE_N", "BLOCK_SIZE_K", "GROUP_SIZE_M", "num_warps", "num_stages"):
                    if type(config.get(key)) is not int or config[key] <= 0:
                        raise ValueError(f"invalid Triton config field {key}")
        if any(pair[0][m]["BLOCK_SIZE_M"] != pair[1][m]["BLOCK_SIZE_M"] for m in expected):
            raise ValueError("Triton top/bottom BLOCK_SIZE_M mismatch")
    return {str(Path(p).resolve()): file_hash(p) for p in files}


def resume_valid(manifest, fingerprint):
    if manifest.get("fingerprint") != fingerprint or manifest.get("status") not in ("validated", "installed"):
        return False
    hashes = manifest.get("artifact_hashes", {})
    return bool(hashes) and all(Path(path).is_file() and file_hash(path) == sha for path, sha in hashes.items())


def merge_csv(old_bytes, new_bytes):
    old = list(csv.DictReader(io.StringIO(old_bytes.decode("utf-8-sig")))) if old_bytes else []
    new_reader = csv.DictReader(io.StringIO(new_bytes.decode("utf-8-sig")))
    new = list(new_reader)
    columns = list(new_reader.fieldnames)
    group = ("arch", "inter_dim", "model_dim", "expert", "topk", "quant_type")
    def group_key(row):
        return tuple(str(row[name]) for name in group)
    identities = {group_key(r): (r["indtype"], r["q_size_n"], r["q_size_k"]) for r in new}
    for row in old:
        key = group_key(row)
        if key in identities and identities[key] != (row.get("indtype"), row.get("q_size_n", "0"), row.get("q_size_k", "0")):
            raise ValueError("ASM native key cannot distinguish existing dtype/group size; refuse collision")
        for name in row:
            if name not in columns:
                columns.append(name)
    rows = {}
    for row in old:
        key = (group_key(row), int(row["token"]))
        if key in rows:
            raise ValueError("existing ASM CSV contains duplicate runtime keys; resolve them before installation")
        rows[key] = row
    for row in new:
        key = (group_key(row), int(row["token"]))
        rows[key] = dict(rows.get(key, {}), **row)
    output = io.StringIO(newline="")
    writer = csv.DictWriter(output, fieldnames=columns)
    writer.writeheader()
    writer.writerows(rows[k] for k in sorted(rows))
    return output.getvalue().encode("utf-8")


def recover_transaction(directory):
    journal_path = Path(directory) / ".moe_tune_transaction.json"
    if not journal_path.exists():
        return
    journal = json.loads(journal_path.read_text())
    if journal["status"] != "pending":
        return
    for entry in journal["entries"]:
        target = Path(entry["target"])
        if target.parent.resolve() != Path(directory).resolve():
            raise ValueError("transaction target outside config directory")
        if entry["backup"] is None:
            target.unlink(missing_ok=True)
        else:
            atomic_write(target, Path(entry["backup"]).read_bytes())
    journal["status"] = "rolled_back"
    write_json(journal_path, journal)


def transactional_replace(directory, replacements):
    """Caller holds directory lock. Recover the previous interrupted install first."""
    directory = Path(directory).resolve()
    recover_transaction(directory)
    transaction = directory / ".moe_tune_backups" / uuid.uuid4().hex
    transaction.mkdir(parents=True)
    entries = []
    for target, content in replacements.items():
        target = Path(target).resolve()
        if target.parent != directory:
            raise ValueError("installation target outside runtime config directory")
        backup = transaction / target.name
        if target.exists():
            backup.write_bytes(target.read_bytes())
        entries.append(dict(target=str(target), backup=str(backup) if target.exists() else None,
                            after_sha256=hashlib.sha256(content).hexdigest()))
    journal = dict(status="pending", entries=entries)
    journal_path = directory / ".moe_tune_transaction.json"
    write_json(journal_path, journal)
    try:
        for target, content in replacements.items():
            atomic_write(target, content)
        journal["status"] = "committed"
        write_json(journal_path, journal)
    except BaseException:
        recover_transaction(directory)
        raise
    write_json(transaction / "receipt.json", journal)
    return dict(receipt=str(transaction / "receipt.json"), files=entries)


def install(spec, backend, files, runtime, *, replace_existing=False):
    directory = Path(runtime[backend + "_config_dir"]).resolve()
    directory.mkdir(parents=True, exist_ok=True)
    with exclusive_lock(directory / ".moe_tune_install.lock"):
        recover_transaction(directory)
        owner_path = directory / ".moe_tune_owners.json"
        owners = json.loads(owner_path.read_text()) if owner_path.exists() else {}
        replacements = {}
        semantic = spec.semantic_key(backend)
        for source in map(Path, files):
            target = directory / source.name
            new = source.read_bytes()
            old = target.read_bytes() if target.exists() else None
            if backend == "asm":
                new = merge_csv(old, new)
            else:
                owner = owners.get(source.name)
                if owner and owner["semantic_key"] != semantic:
                    raise ValueError(f"Triton native filename collision with a different shape contract: {target}")
                if old:
                    old_data, new_data = json.loads(old), json.loads(new)
                    if not owner and not replace_existing:
                        raise ValueError(f"legacy Triton config has no shape provenance: {target}; inspect it before using --replace-existing-configs")
                    if owner and owner.get('target_sha256') != hashlib.sha256(old).hexdigest() and not replace_existing:
                        raise ValueError(f"Triton config changed outside this tuner: {target}; inspect it before using --replace-existing-configs")
                    old_data.update(new_data)
                    new = json.dumps(dict(sorted(old_data.items(), key=lambda x: int(x[0]))), indent=2, allow_nan=False).encode()
                owners[source.name] = dict(semantic_key=semantic, spec=spec.to_dict(),
                                          source_sha256=file_hash(source), target_sha256=hashlib.sha256(new).hexdigest(),
                                          capability=runtime["capability"])
            replacements[target] = new
        if backend == "triton":
            replacements[owner_path] = json.dumps(owners, indent=2, allow_nan=False).encode()
        return transactional_replace(directory, replacements)
