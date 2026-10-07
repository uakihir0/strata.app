"""tools/mtp_rt.py - plan v0.3 P6: the MTP draft layer's runtime files, from the packed MTP GGUF.

    python tools/mtp_rt.py --gguf <Strata>/mtp-bf16/mtp-q2_0.gguf --out <Strata>/mtp-bf16/rt

Writes
  experts.bin   512 routed experts in the engine's blob layout (`include/strata/kernels/cpu/expert.hpp`): gate/up
                rows interleaved (2r = gate r, 2r+1 = up r), then down rows; the Q2_0 codes in one plane and the fp16
                scales in another.  A lossless relayout of the GGUF's Q2_0 blocks (same bytes, `cpu_expert_fixture.py`).
  dense.bin     every other tensor: the large projections quantized to Q8_0 (ggml's reference rounding) so the
                engine's multi-column MMVQ can run them; the hyper-connection and router weights kept BF16; the
                RMSNorm weights as F32 with the Gemma "+1" applied (vLLM GemmaRMSNorm scales by 1 + w).
  dense.txt     one line per tensor: name kind rows cols offset bytes   (kind = q8_0 | bf16 | f32)
"""
from __future__ import annotations

import argparse
import os
import sys
from pathlib import Path

import numpy as np

ROOT = Path(__file__).resolve().parents[1]
sys.path.insert(0, str(ROOT))
sys.path.insert(0, str(Path(__file__).resolve().parent))
from artifact_set_lock import (  # noqa: E402
    ArtifactSetLockError,
    LOCK_FDS_ENV,
    acquire_artifact_set_locks,
    clear_generation_pending,
    mark_generation_pending,
)
from _paths import add_gguf_py  # noqa: E402
add_gguf_py()
import gguf  # noqa: E402

H, FF, NE = 2560, 640, 512
BLOB = 3 * (H * FF * 18 // 64)
Q8 = {"fc_embedding.weight", "fc_hidden.weight", "self_attn.q_proj.weight", "self_attn.k_proj.weight",
      "self_attn.v_proj.weight", "self_attn.o_proj.weight", "self_attn.indexer.index_qk_proj.weight",
      "mlp.shared_expert.gate_proj.weight", "mlp.shared_expert.up_proj.weight", "mlp.shared_expert.down_proj.weight"}


def q8_0(x: np.ndarray) -> bytes:
    """ggml quantize_row_q8_0_ref over rows of a 2-D float32 array: 32-value blocks, fp16 d = amax / 127."""
    b = x.reshape(-1, 32).astype(np.float32)
    amax = np.abs(b).max(axis=1)
    d = amax / 127.0
    inv = np.where(d > 0, 1.0 / np.where(d > 0, d, 1.0), 0.0).astype(np.float32)
    v = b * inv[:, None]
    q = (np.sign(v) * np.floor(np.abs(v) + 0.5)).astype(np.int8)
    out = np.empty((b.shape[0], 34), dtype=np.uint8)
    out[:, :2] = d.astype(np.float16).view(np.uint8).reshape(-1, 2)
    out[:, 2:] = q.view(np.uint8)
    return out.tobytes()


def blob_of(gu: np.ndarray, dn: np.ndarray) -> bytes:
    """gu: (1280, 720) Q2_0 rows (gate rows 0..639, up rows 640..1279); dn: (2560, 180)."""
    gub = gu.reshape(2 * FF, H // 64, 18)
    inter = np.empty_like(gub)
    inter[0::2] = gub[:FF]
    inter[1::2] = gub[FF:]
    dnb = dn.reshape(H, FF // 64, 18)
    parts = [inter[:, :, 2:].tobytes(), dnb[:, :, 2:].tobytes(), inter[:, :, :2].tobytes(), dnb[:, :, :2].tobytes()]
    out = b"".join(parts)
    if len(out) != BLOB:
        raise ValueError(f"canonical MTP expert blob is {len(out)} bytes, expected {BLOB}")
    return out


def _write_runtime(gguf_path: str, out: Path) -> int:
    out.mkdir(parents=True, exist_ok=True)
    r = gguf.GGUFReader(gguf_path)
    tens = {t.name: t for t in r.tensors}
    gu = np.asarray(tens["mtp.layers.0.mlp.experts.gate_up_proj"].data)
    dn = np.asarray(tens["mtp.layers.0.mlp.experts.down_proj"].data)
    expected_gu = (NE, 2 * FF, H // 64 * 18)
    expected_dn = (NE, H, FF // 64 * 18)
    if gu.shape != expected_gu or dn.shape != expected_dn:
        raise ValueError(
            "MTP expert GGUF shapes are invalid: "
            f"gate_up={gu.shape} (expected {expected_gu}), "
            f"down={dn.shape} (expected {expected_dn})"
        )
    with open(out / "experts.bin", "wb") as f:
        for e in range(NE):
            f.write(blob_of(gu[e], dn[e]))
    lines = []
    off = 0
    with open(out / "dense.bin", "wb") as f:
        for name, t in tens.items():
            if "experts." in name:
                continue
            short = name[len("mtp."):]
            short = short[len("layers.0."):] if short.startswith("layers.0.") else short
            data = np.asarray(t.data)
            if int(t.tensor_type) == 0:        # F32 norm weights: raw GemmaRMSNorm w -> 1 + w
                arr = (data.astype(np.float32) + 1.0)
                raw, kind, rows, cols = arr.tobytes(), "f32", 1, arr.size
            else:                              # BF16
                u16 = data.view(np.uint16) if data.dtype != np.uint16 else data
                u16 = u16.reshape(data.shape[0], -1)
                rows, cols = u16.shape
                if short in Q8:
                    f32 = (u16.astype(np.uint32) << 16).view(np.float32)
                    raw, kind = q8_0(f32), "q8_0"
                else:
                    raw, kind = u16.tobytes(), "bf16"
            pad = (-off) % 256
            f.write(b"\0" * pad)
            off += pad
            f.write(raw)
            lines.append(f"{short} {kind} {rows} {cols} {off} {len(raw)}")
            off += len(raw)
    (out / "dense.txt").write_text("\n".join(lines) + "\n", encoding="utf-8")
    print(f"experts.bin {NE * BLOB} B, dense.bin {off} B, {len(lines)} tensors -> {out}")
    for l in lines:
        print("  " + l)
    return 0


def _sync_runtime_files(out: Path) -> None:
    """Make completed runtime data durable before a generation marker can be removed."""
    for name in ("experts.bin", "dense.bin", "dense.txt"):
        # These files are generated here while the writer lock excludes readers.
        fd = os.open(out / name, os.O_RDWR)
        try:
            os.fsync(fd)
        finally:
            os.close(fd)
    directory_fd = os.open(out, os.O_RDONLY)
    try:
        os.fsync(directory_fd)
    finally:
        os.close(directory_fd)


def _invalidate_runtime_source(out: Path, source_file: str) -> None:
    """A standalone conversion has no trusted source stamp; require fresh attestation."""
    try:
        (out / source_file).unlink()
    except FileNotFoundError:
        return
    directory_fd = os.open(out, os.O_RDONLY)
    try:
        os.fsync(directory_fd)
    finally:
        os.close(directory_fd)


def main() -> int:
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--gguf", required=True)
    ap.add_argument("--out", required=True)
    a = ap.parse_args()
    out = Path(a.out)
    try:
        locks = acquire_artifact_set_locks(
            [Path(a.gguf).parent], [(out, True)],
            inherited=os.environ.get(LOCK_FDS_ENV)
        )
    except ArtifactSetLockError as exc:
        print(f"mtp_rt: {exc}", file=sys.stderr)
        return 2
    owns_generation = not locks.is_borrowed(out)
    try:
        if owns_generation:
            mark_generation_pending(out)
        result = _write_runtime(a.gguf, out)
        if result == 0:
            from mtp_runtime_support import MTP_RUNTIME_SOURCE_FILE, mtp_runtime_valid

            if not mtp_runtime_valid(out):
                print(
                    "mtp_rt: generated runtime failed structural validation; "
                    "the pending-generation marker is retained",
                    file=sys.stderr,
                )
                return 3
            try:
                _sync_runtime_files(out)
                if owns_generation:
                    _invalidate_runtime_source(out, MTP_RUNTIME_SOURCE_FILE)
            except OSError as exc:
                print(
                    f"mtp_rt: could not durably publish runtime output: {exc}; "
                    "the pending-generation marker is retained",
                    file=sys.stderr,
                )
                return 3
            if owns_generation:
                clear_generation_pending(out)
        return result
    finally:
        locks.close()


if __name__ == "__main__":
    sys.exit(main())
