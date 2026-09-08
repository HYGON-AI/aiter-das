# SPDX-License-Identifier: MIT
import os
import functools
import subprocess


_PERF_MODEL_CHIP_ARCHS = {
    # Perf Model selects the simulated chip independently from the compiler.
    # Its virtual device cannot reliably answer hipcc's ``native`` target
    # discovery, so keep the build target explicit when Shaobo is requested.
    "sb": "gfx946",
}


def get_configured_gfx():
    """Return the explicit or Perf-Model-derived compiler target.

    ``GPU_ARCHS`` remains authoritative. Only a known Perf Model chip is
    translated when that variable is absent; physical GPU environments retain
    the historical ``native`` fallback.
    """
    gfx = os.getenv("GPU_ARCHS", "").strip()
    if gfx:
        return gfx
    gpu_chip = os.getenv("GPU_CHIP", "").strip().lower()
    return _PERF_MODEL_CHIP_ARCHS.get(gpu_chip, "native")


def _gfx_from_kfd_target_version(ver: int) -> str:
    """Decode KFD gfx_target_version (major*10000 + minor*100 + step)."""
    if ver <= 0:
        return ""
    major = ver // 10000
    minor = (ver // 100) % 100
    step = ver % 100
    # gfx90a / gfx92a use hex stepping (10 → a).
    step_s = format(step, "x") if step >= 10 else str(step)
    return f"gfx{major}{minor}{step_s}"


def _gfx_from_kfd_sysfs() -> str:
    """Read gfx from KFD sysfs so we do not need HSA (amdgpu-arch/rocminfo)."""
    import glob

    versions = []
    for path in glob.glob("/sys/class/kfd/kfd/topology/nodes/*/properties"):
        try:
            with open(path, "r") as f:
                for line in f:
                    if line.startswith("gfx_target_version"):
                        ver = int(line.split()[-1])
                        if ver > 0:
                            versions.append(ver)
                        break
        except (OSError, ValueError):
            continue
    if not versions:
        return ""
    return _gfx_from_kfd_target_version(versions[0])


@functools.lru_cache(maxsize=1)
def get_gfx():
    gfx = get_configured_gfx()
    if gfx != "native":
        return gfx
    try:
        result = subprocess.run(
            ["rocminfo"], stdout=subprocess.PIPE, stderr=subprocess.PIPE, text=True
        )
        for line in result.stdout.split("\n"):
            if "gfx" in line.lower():
                return line.split(":")[-1].strip()
    except Exception:
        pass
    kfd_gfx = _gfx_from_kfd_sysfs()
    if kfd_gfx:
        return kfd_gfx
    raise RuntimeError(
        "cannot determine GPU arch (rocminfo/amdgpu-arch empty). "
        "Set GPU_ARCHS, e.g. GPU_ARCHS=gfx938"
    )


@functools.lru_cache(maxsize=1)
def get_cu_num():
    import torch

    device = torch.cuda.current_device()
    cu_num = torch.cuda.get_device_properties(device).multi_processor_count
    return cu_num


# HCU architecture capability metadata for import planning and feature guards.
# This table is intentionally read-only metadata: it must not change get_gfx()
# or get_cu_num() behavior. Numeric CU values are reference maxima from local
# HCU hardware notes, not the runtime CU count for a concrete SKU/board. Use
# get_cu_num() for live dispatch, tuning, or partition decisions.
HCU_ARCH_CAPABILITIES = {
    "gfx928": {
        "reference_max_cu": 128,
        "vgpr_kb": 512,
        "l1_kb": None,
        "l2": "8MB/32TCC",
        "lds_kb": 64,
        "read_write_cnt_split": False,
        "fp8": False,
        "fp6": False,
        "fp4": False,
        "int4": "partial_or_incomplete",
        "mxf": False,
        "tls_load_to_lds": False,
        "matrix_store": False,
    },
    "gfx936": {
        "reference_max_cu": 88,
        "vgpr_kb": 768,
        "l1_kb": 32,
        "l2": "8MB/32TCC",
        "lds_kb": 64,
        "read_write_cnt_split": True,
        "fp8": False,
        "fp6": False,
        "fp4": False,
        "int4": False,
        "mxf": False,
        "tls_load_to_lds": False,
        "matrix_store": False,
    },
    "gfx938": {
        "reference_max_cu": 72,
        "vgpr_kb": 768,
        "l1_kb": 32,
        "l2": "8MB/32TCC",
        "lds_kb": 64,
        "read_write_cnt_split": True,
        "fp8": True,
        "fp6": False,
        "fp4": False,
        "int4": True,
        "mxf": False,
        "tls_load_to_lds": False,
        "matrix_store": False,
    },
    "gfx92a": {
        "reference_max_cu": 128,
        "vgpr_kb": 512,
        "l1_kb": 16,
        "l2": None,
        "lds_kb": 64,
        "lds_allocation_granularity_kb": 1,
        "read_write_cnt_split": False,
        "fp8": True,
        "fp6": True,
        "fp4": True,
        "int4": False,
        "mxf": False,
        "tls_load_to_lds": True,
        "matrix_store": False,
    },
    "gfx946": {
        "reference_max_cu": 192,
        "cu_layout": "4x48",
        "vgpr_kb": 512,
        "l1_kb": 32,
        "l2": "6MB/16TCC",
        "l2_cache_line_bytes": 256,
        "lds_kb": 128,
        "read_write_cnt_split": True,
        "fp8": True,
        "fp6": True,
        "fp4": True,
        "int4": True,
        "mxf": True,
        "tls_load_to_lds": True,
        "matrix_store": True,
    },
}


def _split_gfx_targets(gfxs):
    if gfxs is None:
        gfxs = get_gfx()
    if isinstance(gfxs, str):
        return [
            item.strip().lower()
            for part in gfxs.split(";")
            for item in part.split(",")
            if item.strip()
        ]
    return [str(item).strip().lower() for item in gfxs if str(item).strip()]


def get_hcu_arch_capability(gfx=None):
    targets = _split_gfx_targets(gfx)
    if not targets:
        return {}
    return dict(HCU_ARCH_CAPABILITIES.get(targets[0], {}))


def get_hcu_arch_capabilities(gfxs=None):
    return {
        gfx: dict(HCU_ARCH_CAPABILITIES.get(gfx, {}))
        for gfx in _split_gfx_targets(gfxs)
    }


def has_hcu_arch_capability(name, gfx=None):
    return get_hcu_arch_capability(gfx).get(name) is True
