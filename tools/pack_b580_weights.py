"""Pack and transform Small or full VK102 model blocks into B580 FP16/FP32 cold buffers."""
from __future__ import annotations

import argparse
import hashlib
import importlib.util
import json
import shutil
import struct
import sys
from pathlib import Path
import numpy as np

MODEL_TOOLS = Path(__file__).resolve().parents[1] / "third_party/dlssnr_amd_model_tools"
EXTRACTED: Path
COLD_OUT: Path
PROFILE: dict

# Every finite E4M3 value is exactly representable in binary16.
def e4m3_half_bits(code: int) -> int:
    e, m = (code >> 3) & 15, code & 7
    if e == 15 and m == 7:
        return 0x7E00
    value = m / 512.0 if e == 0 else (1.0 + m / 8.0) * 2.0 ** (e - 7)
    if code & 128:
        value = -value
    return struct.unpack("<H", struct.pack("<e", value))[0]

LUT_U16 = np.asarray([e4m3_half_bits(i) for i in range(256)], dtype="<u2")

def sha256_bytes(data: bytes) -> str:
    return hashlib.sha256(data).hexdigest()


def tile_transform(buf: bytes, N: int, K: int) -> bytes:
    a = np.frombuffer(buf, dtype="<u2").reshape(N, K)
    return a.reshape(N // 16, 16, K // 16, 16).transpose(0, 2, 1, 3).copy().tobytes()


def apply_tile_ranges(blob: bytearray, ranges: list[tuple[int, int, int, int]]) -> bytes:
    out = bytearray(blob)
    for start, end, N, K in ranges:
        assert end - start == N * K * 2, (start, end, N, K)
        out[start:end] = tile_transform(bytes(out[start:end]), N, K)
    return bytes(out)


PRE_REGIONS = [
    ("mlp_expand", 0, 4096, 128, 32, 8, "matrix"),
    ("mlp_contract", 4096, 8192, 32, 128, 2, "matrix"),
    ("input_lift", 8208, 9232, 32, 16, None, "fp16"),
    ("residual_scale", 9232, 9312, None, None, None, "fp16"),
    ("qkv", 9312, 12384, 96, 32, 6, "matrix"),
    ("attn_pos_bias", 12384, 20576, None, None, None, "fp16"),
    ("scalars_b", 20576, 20592, None, None, None, "f32"),
    ("attn_out_proj", 20592, 21616, 32, 32, 2, "matrix"),
    ("attn_residual_scale", 21616, 21696, None, None, None, "fp16"),
]

POST_REGIONS = [
    ("mlp_expand", 0, 4096, 128, 32, 8, "matrix"),
    ("mlp_contract", 4096, 8192, 32, 128, 2, "matrix"),
    ("residual_scale", 8208, 8272, None, None, None, "fp16"),
    ("main_gain", 8272, 8336, None, None, None, "fp16"),
    ("skip_gain", 8336, 8400, None, None, None, "fp16"),
    ("qkv", 8400, 11472, 96, 32, 6, "matrix"),
    ("attn_pos_bias", 11472, 19664, None, None, None, "fp16"),
    ("scalars_b", 19664, 19680, None, None, None, "f32"),
    ("attn_out_proj", 19680, 20704, 32, 32, 2, "matrix"),
    ("attn_residual_scale", 20704, 20784, None, None, None, "fp16"),
    ("out_project", 20784, 21808, 16, 32, None, "fp16"),
]


def fragment_indices(N: int, K: int, inner: int) -> np.ndarray:
    n, k = np.indices((N, K))
    return (
        (n // 16 % inner) * 512
        + (k // 32) * 512 * inner
        + (n // 16 // inner) * 512 * inner * (K // 32)
        + (4 * (n % 8) + (k % 8) // 2) * 16
        + (n % 16 // 8) * 8
        + 2 * (k % 32 // 8)
        + k % 2
    )


def pack_ioport(block: int, C: int, family_mod) -> tuple[bytes, bytes]:
    shape_block = int(PROFILE["ioport_shapes"][str(block)])
    name = f"block{block}.layer0.layer"
    payload = (EXTRACTED / "inventory" / "weights" / f"{name}.bin").read_bytes()
    if shape_block in (0, 30):
        regions = PRE_REGIONS if shape_block == 0 else POST_REGIONS
        directory = "unpacked-preblock" if shape_block == 0 else "unpacked-postblock"
    elif shape_block == 19:
        regions = [
            ("weight", 0, 524288, 512, 1024, 32, "matrix"),
            ("skip_weight", 524288, 525312, None, None, None, "fp16"),
        ]
        directory = "unpacked-splitswin"
    else:
        ci, co = (C, 2 * C) if shape_block in (2, 4, 6, 8) else (2 * C, C)
        regions = family_mod.regions(C, C // 32, ci, co)
        directory = "unpacked"

    blob = bytearray()
    raw_parts = {}

    def put(role: str, data: bytes):
        off = (len(blob) + 255) // 256 * 256
        blob.extend(bytes(off - len(blob)))
        blob.extend(data)

    for role, start, end, N, K, inner, kind in regions:
        if role == "tail":
            continue
        ext_path = EXTRACTED / directory / f"{name}.{role}.bin"
        ext = ext_path.read_bytes()
        region = payload[start:end]
        if kind == "matrix":
            si = fragment_indices(N, K, inner)
            recovered = np.frombuffer(region, np.uint8)[si].tobytes()
            assert recovered == ext, (block, role, "packed/extracted matrix mismatch")
            data = LUT_U16[np.frombuffer(ext, np.uint8)].tobytes()
        elif role == "out_project":
            n, k = np.indices((16, 32))
            si = (k // 16) * 256 + 32 * (n % 8) + 8 * ((k % 8) // 2) + 4 * (n // 8) + k % 2 + 2 * (k % 16 // 8)
            data = np.frombuffer(region, "<u2")[si].tobytes()
            assert data == ext, "post out_project extracted mismatch"
        elif role == "input_lift":
            assert region == ext, "pre input_lift extracted mismatch"
            # The source tensor is in the lane/byte scatter layout; the author
            # reference reconstructs the logical 32x16 matrix with this inverse.
            # The shader loads the logical matrix at p7.x+g*128, so store the
            # scattered (logical) matrix, not the raw file order.
            n, k = np.indices((32, 16))
            si = (n // 16) * 256 + 32 * (n % 8) + 8 * ((k % 8) // 2) + 4 * (n // 8 % 2) + k % 2 + 2 * (k // 8)
            data = np.frombuffer(ext, "<u2")[si].tobytes()
        else:
            assert region == ext, (block, role, "raw extracted mismatch")
            data = ext
        raw_parts[role] = data
        put(role, data)

    aux = bytearray()
    if shape_block != 19:
        rs = np.frombuffer(raw_parts["residual_scale"], "<u2")
        rbase = 8 if np.all(rs[:8] == 0) else 0
        if shape_block in (0, 30):
            normalized = bytes(16) + rs[rbase : rbase + C].tobytes() + bytes(16)
            put("body_residual_scale", normalized)
        if shape_block in (22, 24, 26, 28):
            gain = np.frombuffer(raw_parts["upsample_gain"], "<u2")
            if C > 32:
                gain = np.concatenate((rs[C : C + 16], gain))
            assert len(gain) == C
            put("blend_gain", gain.tobytes())
        if shape_block == 30:
            put("blend_gain", raw_parts["skip_gain"] + raw_parts["main_gain"])
        bias = np.frombuffer(raw_parts["attn_pos_bias"], "<u2")
        i, j = np.indices((64, 64))
        si = (
            (4 * (i // 16) + j // 16) * 256
            + (4 * (i % 8) + (j % 8) // 2) * 8
            + (j % 2)
            + (i % 16 // 8) * 2
            + (j % 16 // 8) * 4
        )
        canonical = np.stack([bias[h * 4096 + si] for h in range(C // 32)])
        aux.extend(canonical.view("<f2").astype("<f4").tobytes())
        aux.extend(raw_parts["scalars_b"])

    # Apply S1 / R4 16x16 B-tile transformations.
    # GPU A/B (runs 005 vs 007) rejects the "canonical pre/post pack" hypothesis:
    # canonical made b0 worse (mean_abs 0.094 -> 0.394), so keep TILE16.
    if shape_block == 0:
        ranges = [(0, 8192, 128, 32), (8192, 16384, 32, 128), (17664, 23808, 96, 32), (32256, 34304, 32, 32)]
    elif shape_block == 30:
        ranges = [(0, 8192, 128, 32), (8192, 16384, 32, 128), (17152, 23296, 96, 32), (31744, 33792, 32, 32)]
    elif shape_block == 19:
        ranges = [(0, 1048576, 512, 1024)]
    elif shape_block == 2:
        ranges = [(33536, 37632, 64, 32)]
    elif shape_block == 4:
        ranges = [(107264, 123648, 128, 64)]
    elif shape_block == 6:
        ranges = [(361472, 427008, 256, 128)]
    elif shape_block == 8:
        ranges = [(1312256, 1574400, 512, 256)]
    elif shape_block == 22:
        ranges = [(720896, 983040, 256, 512)]
    elif shape_block == 24:
        ranges = [(196608, 262144, 128, 256)]
    elif shape_block == 26:
        ranges = [(57344, 73728, 64, 128)]
    elif shape_block == 28:
        ranges = [(16384, 20480, 32, 64)]
    else:
        raise ValueError(block)

    transformed = apply_tile_ranges(blob, ranges)
    return transformed, bytes(aux or bytes(4))


SWIN_ROLES = (
    "attn_out_proj",
    "attn_pos_bias",
    "attn_residual_scale",
    "mlp_contract",
    "mlp_expand",
    "mlp_mid",
    "qkv",
    "residual_scale",
    "scalars_b",
)


def pack_swin(block: int, c: int, unpacked_manifest: dict) -> tuple[bytes, bytes]:
    record = f"block{block}.layer0.layer"
    layer = next(x for x in unpacked_manifest["layers"] if x["record"] == record)
    assert layer["C"] == c and layer["heads"] == c // 32
    raw = (EXTRACTED / "inventory" / "weights" / f"{record}.bin").read_bytes()
    tensors = {x["name"]: x for x in layer["tensors"]}
    unpacked = EXTRACTED / "unpacked"
    pack = bytearray()
    ext_bytes = {}
    role_off = {}
    for role in (r for r in SWIN_ROLES if c != 32 or r != "mlp_mid"):
        t = tensors[role]
        ext = (unpacked / f"{record}.{role}.bin").read_bytes()
        start, end = t["src_range"]
        if t["kind"] == "matrix":
            nrows, kcols = t["N"], t["K"]
            inner = 8 if role == "mlp_expand" else 2 if role == "mlp_mid" else nrows // 16
            si = fragment_indices(nrows, kcols, inner)
            recovered = np.frombuffer(raw[start:end], np.uint8)[si].tobytes()
            assert recovered == ext, (block, role)
            data = LUT_U16[np.frombuffer(ext, np.uint8)].tobytes()
        else:
            assert raw[start:end] == ext, (block, role)
            data = ext
        pack.extend(bytes((-len(pack)) % 256))
        role_off[role] = len(pack)
        pack.extend(data)
        ext_bytes[role] = ext

    bias = np.frombuffer(ext_bytes["attn_pos_bias"], "<u2")
    i, j = np.indices((64, 64))
    si = (
        (4 * (i // 16) + j // 16) * 256
        + (4 * (i % 8) + (j % 8) // 2) * 8
        + (j % 2)
        + (i % 16 // 8) * 2
        + (j % 16 // 8) * 4
    )
    canonical = np.stack([bias[h * 4096 + si] for h in range(c // 32)])
    aux = bytearray(canonical.view("<f2").astype("<f4").tobytes())
    aux.extend(ext_bytes["scalars_b"])

    if c == 32:
        ranges = [(0, 2048, 32, 32), (10496, 18688, 32, 128), (18688, 26880, 128, 32), (26880, 33024, 96, 32)]
    elif c == 64:
        ranges = [(0, 8192, 64, 64), (24832, 33024, 64, 64), (33024, 65792, 256, 64), (82176, 106752, 192, 64)]
    elif c == 128 and block == PROFILE["downsample_blocks"][2]:
        ranges = [(0, 32768, 128, 128), (65792, 98560, 128, 128), (98560, 229632, 512, 128), (262400, 360704, 384, 128)]
    elif c == 128:
        ranges = [(0, 32768, 128, 128), (66048, 98816, 128, 128), (98816, 229888, 512, 128), (262656, 360960, 384, 128)]
    elif c == 256 and block == PROFILE["downsample_blocks"][3]:
        ranges = [(197120, 328192, 256, 256), (328192, 852480, 1024, 256)]
    elif c == 256:
        ranges = [(197376, 328448, 256, 256), (328448, 852736, 1024, 256)]
    else:
        raise ValueError((block, c))

    # C256 attn_out_proj and qkv were left canonical in the first Small pack,
    # but the C256 body family loads them as MAT_B 16x16 tiles
    # (c256_common.glsl / c256_d4_epi_only.comp: coopMatLoad(b, pack,
    # wo + n0*256 + k0, 256, LCOL)).  Apply the same (N/16,K/16,16,16)
    # transform the C32/C64/C128 packs already use.
    if c == 256 and PROFILE["backend_key"] == "small":
        for role, n, k in (("attn_out_proj", 256, 256), ("qkv", 768, 256)):
            off = role_off[role]
            ranges.append((off, off + n * k * 2, n, k))

    transformed = apply_tile_ranges(pack, ranges)
    return transformed, bytes(aux)


def bits_field(x: np.ndarray, positions: list[int]) -> np.ndarray:
    v = np.zeros_like(x, dtype=np.int64)
    for b, dest in enumerate(positions):
        v |= ((x >> b) & 1) << dest
    return v


def tile16_indices(N: int, K: int) -> np.ndarray:
    n = np.arange(N, dtype=np.int64)[:, None]
    k = np.arange(K, dtype=np.int64)[None, :]
    return ((n // 16) * (K // 16) * 256 + (k // 16) * 256
            + (n % 16) * 16 + k % 16)


def ffwd_maps():
    # S20's L0 payload is not a plain row-major 512x512 matrix: the upstream
    # unpacker's three ffwd maps interleave two payload matrices.  The exact
    # consumer binding is still unproven (analysis/weights/proof.json), so this
    # pack keeps the previously verified value-multiset maps rather than an
    # unverified TILE16 rewrite.
    g = np.arange(8)[:, None, None]
    r = np.arange(64)[None, :, None]
    k = np.arange(512)[None, None, :]
    a = bits_field(g, [11, 12, 13]) | bits_field(r, [3, 6, 7, 8, 9, 10]) | bits_field(k, [0, 4, 5, 1, 2, 14, 15, 16, 17])
    j = np.arange(256)[None, :, None]
    r2 = np.arange(64)[None, None, :]
    q0 = 262144 + g * 16384 + (bits_field(r2, [1, 0, 4, 5, 2, 13]) | bits_field(j, [6, 3, 9, 7, 8, 10, 11, 12]))
    n = np.arange(64)[None, :, None]
    j2 = np.arange(256)[None, None, :]
    q2 = 393216 + g * 16384 + (bits_field(j2, [0, 1, 2, 4, 5, 11, 12, 13]) | bits_field(n, [6, 7, 8, 3, 9, 10]))
    return a, q0, q2


def matrix_map(N: int, K: int) -> np.ndarray:
    n = np.arange(N)[:, None]
    k = np.arange(K)[None, :]
    lane = 4 * (n % 8) + (k % 8) // 2
    byte = 2 * ((k % 32) // 8) + k % 2
    return ((k // 32) * (N // 16) + n // 16) * 512 + lane * 16 + (n % 16 // 8) * 8 + byte


def pack_split16(block: int) -> tuple[bytes, bytes]:
    packed = bytearray()

    def add(data: bytes):
        off = (len(packed) + 255) & ~255
        packed.extend(bytes(off - len(packed)))
        packed.extend(data)

    sw = EXTRACTED / "unpacked-splitswin"
    # Write the canonical L0 matrices; the (0,524288,512,512),
    # (524288,786432,2048,64), (786432,1048576,512,256) ranges below apply the
    # consumer TILE16 transform once.  The old ffwd_maps pre-permuted them and
    # then the ranges permuted again.
    if PROFILE["backend_key"] == "102":
        # VK102 S20 consumes the original per-head ffwd maps before TILE16.
        raw = np.frombuffer((EXTRACTED / "inventory/weights" / f"block{block}.layer0.layer.bin").read_bytes(), np.uint8)
        amap, bmap0, bmap2 = ffwd_maps()
        add(LUT_U16[raw[amap]].tobytes())
        add(LUT_U16[raw[bmap0]].tobytes())
        add(LUT_U16[raw[bmap2]].tobytes())
    else:
        a = LUT_U16[np.frombuffer((sw / f"block{block}.layer0.layer.ffwd_a.bin").read_bytes(), np.uint8)].tobytes()
        b = LUT_U16[np.frombuffer((sw / f"block{block}.layer0.layer.ffwd_b.bin").read_bytes(), np.uint8)].tobytes()
        assert len(a) == 524288 and len(b) == 524288, (block, len(a), len(b))
        add(a)
        add(b[:262144])
        add(b[262144:])

    auxiliary = b""
    for layer, role, N in ((1, "ff_proj", 512), (2, "qkv", 1536), (3, "out_proj", 512)):
        name = f"block{block}.layer{layer}.layer"
        raw = (EXTRACTED / "inventory" / "weights" / f"{name}.bin").read_bytes()
        canonical = np.frombuffer(raw, np.uint8)[matrix_map(N, 512)]
        ext = EXTRACTED / "unpacked-splitswin" / (name + (".qkv.bin" if layer == 2 else ".weight.bin"))
        assert canonical.tobytes() == ext.read_bytes(), str(ext)
        add(LUT_U16[canonical].tobytes())
        if layer != 2:
            ext_skip = EXTRACTED / "unpacked-splitswin" / f"{name}.skip_weight.bin"
            assert raw[N * 512 :] == ext_skip.read_bytes() and len(raw[N * 512 :]) == 1024
            add(ext_skip.read_bytes())
        else:
            bias_path = EXTRACTED / "unpacked-splitswin" / f"{name}.attn_pos_bias.bin"
            scale_path = EXTRACTED / "unpacked-splitswin" / f"{name}.tail.bin"
            assert raw[786432:917504] == bias_path.read_bytes()
            assert raw[917504:917568] == scale_path.read_bytes()
            raw_bias = np.frombuffer(bias_path.read_bytes(), "<f2")
            h, i, j = np.indices((16, 64, 64), dtype=np.int64)
            lane = 4 * (i % 8) + (j % 8) // 2
            sl = (j % 2) | ((i % 16 // 8) << 1) | ((j % 16 // 8) << 2)
            index = h * 4096 + (4 * (i // 16) + j // 16) * 256 + lane * 8 + sl
            bias = raw_bias[index].astype("<f4")
            scales = np.frombuffer(scale_path.read_bytes(), "<f4")
            assert scales.size == 16 and np.all(np.isfinite(scales))
            auxiliary = bias.tobytes() + scales.tobytes()

    if block == PROFILE["split_last"]:
        name = f"block{block}.layer4.layer"
        raw4 = (EXTRACTED / "inventory" / "weights" / f"{name}.bin").read_bytes()
        ext4 = EXTRACTED / "unpacked-splitswin" / f"{name}.weight.bin"
        canonical4 = np.frombuffer(raw4, np.uint8)[matrix_map(1024, 512)]
        assert canonical4.tobytes() == ext4.read_bytes()
        # Keep the prior canonical pack: the final-head consumer binding is
        # still unproven (analysis/weights/proof.json).
        add(LUT_U16[canonical4].tobytes())

    ranges = [
        (0, 524288, 512, 512),
        (524288, 786432, 2048, 64),
        (786432, 1048576, 512, 256),
        (1573888, 3146752, 1536, 512),
        (3146752, 3671040, 512, 512),
    ]
    if block == PROFILE["split_last"] and PROFILE["backend_key"] == "102":
        # Frozen VK102 S24 and S25 retain canonical last-head projection weights.
        ranges = [r for r in ranges if r[0] != 3146752]
    if block == PROFILE["split_last"] and PROFILE["backend_key"] == "small":
        # Final-head L4.weight is read as MAT_B 16x16 tiles; it is outside the
        # L0-L3 ranges above.
        ranges.append((3672064, 4720640, 1024, 512))
    transformed = apply_tile_ranges(packed, ranges)
    return transformed, auxiliary


def vit_canonical(raw: bytes, n: int, k: int, qkv: bool = False) -> np.ndarray:
    r = np.arange(n, dtype=np.int32)[:, None]
    c = np.arange(k, dtype=np.int32)[None, :]
    if qkv:
        which, r = r // 1024, r % 1024
        b = (
            (c & 1)
            | ((c >> 1 & 1) << 4)
            | ((c >> 2 & 1) << 5)
            | ((c >> 3 & 1) << 1)
            | ((c >> 4 & 1) << 2)
            | ((r & 1) << 6)
            | ((r >> 1 & 1) << 7)
            | ((r >> 2 & 1) << 8)
            | ((r >> 3 & 1) << 3)
            | ((r >> 4 & 1) << 9)
        )
        addr = 128 + (3 * ((r >> 5) | ((c >> 5) << 5)) + which) * 1024 + b
    else:
        addr = (
            (c // 32) * (n // 16) * 512
            + (r // 16) * 512
            + (4 * (r % 8) + (c % 8) // 2) * 16
            + ((r % 16) // 8) * 8
            + 2 * ((c % 32) // 8)
            + c % 2
        )
    return np.frombuffer(raw, dtype=np.uint8)[addr]


def pack_vit(block: int) -> tuple[bytes, bytes]:
    rec = {}
    for layer in range(5):
        name = f"block{block}.layer{layer}.layer"
        rec[layer] = (EXTRACTED / "inventory" / "weights" / f"{name}.bin").read_bytes()
    pack = bytearray()
    for role, layer, n, k in [("WE", 0, 4096, 1024), ("WC", 1, 1024, 4096), ("WQ", 2, 3072, 1024), ("WO", 4, 1024, 1024)]:
        codes = vit_canonical(rec[layer], n, k, role == "WQ")
        parts = ["q", "k", "v"] if role == "WQ" else ["weight"]
        ext_parts = [(EXTRACTED / "unpacked-vit" / f"block{block}.layer{layer}.layer.{p}.bin").read_bytes() for p in parts]
        assert codes.tobytes() == b"".join(ext_parts), (block, role)
        bits = LUT_U16[codes]
        physical = bits.reshape(n // 32, 32, k // 16, 16).transpose(0, 2, 1, 3).copy()
        pack.extend(physical.tobytes())
    for role, layer, matrix_bytes in [("RS", 1, 1024 * 4096), ("ARS", 4, 1024 * 1024)]:
        raw = rec[layer][matrix_bytes:]
        ext = (EXTRACTED / "unpacked-vit" / f"block{block}.layer{layer}.layer.skip_weight.bin").read_bytes()
        assert len(raw) == 2048 and ext == raw, (block, role)
        pack.extend(raw)
    scalars = rec[2][:128]
    assert np.isfinite(np.frombuffer(scalars, dtype="<f4")).all()
    return bytes(pack), scalars


def save_cold(logical_name: str, filename_suffix: str, data: bytes, index: dict) -> Path:
    digest = sha256_bytes(data)
    out_name = f"{digest}__{filename_suffix}"
    out_path = COLD_OUT / out_name
    out_path.write_bytes(data)
    index[logical_name] = {
        "logical_name": logical_name,
        "path": str(out_path),
        "bytes": len(data),
        "sha256": digest,
    }
    return out_path


def main():
    global EXTRACTED, COLD_OUT, PROFILE
    parser = argparse.ArgumentParser(description="Prepare B580 FP16 cold resources from verified model tensors")
    parser.add_argument("--profile", choices=["small", "vk102"], default="small")
    parser.add_argument("--extracted", type=Path, required=True)
    parser.add_argument("--out", type=Path, required=True)
    parser.add_argument("--manifest", type=Path, required=True)
    args = parser.parse_args()
    PROFILE = json.loads((Path(__file__).with_name("model_profiles.json")).read_text(encoding="utf-8"))[args.profile]
    EXTRACTED = args.extracted.resolve()
    COLD_OUT = args.out.resolve()
    if COLD_OUT.exists() and any(COLD_OUT.iterdir()):
        raise SystemExit("Output must be a new or empty directory")
    COLD_OUT.mkdir(parents=True, exist_ok=True)

    spec = importlib.util.spec_from_file_location("unpack_swin_family", MODEL_TOOLS / "unpack_swin_family.py")
    family_mod = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(family_mod)

    unpacked_manifest = json.loads((EXTRACTED / "unpacked" / "manifest.json").read_text(encoding="utf-8"))
    index = {}

    shape_width = {0:32, 2:32, 4:64, 6:128, 8:256, 19:512, 22:256, 24:128, 26:64, 28:32, 30:32}
    for block, shape in PROFILE["ioport_shapes"].items():
        b, c = int(block), shape_width[shape]
        w, aux = pack_ioport(b, c, family_mod)
        save_cold(f"ioport_{b}_ioport_pack", f"ioport_{b}_ioport_pack.fp16.bin", w, index)
        if b in (0, PROFILE["post_block"]):
            save_cold(f"ioport_{b}_ioport_body_aux", "ioport_aux.f32.bin", aux, index)
        print(f"Packed ioport_{b}: weights={len(w)}B aux={len(aux)}B")
    for block, c in PROFILE["swin_blocks"].items():
        b = int(block)
        w, aux = pack_swin(b, c, unpacked_manifest)
        save_cold(f"swin_{b}_weights", f"swin_{b}_weights.fp16.bin", w, index)
        save_cold(f"swin_{b}_aux", f"c{c}_aux.bin", aux, index)
    for b in PROFILE["split_blocks"]:
        w, aux = pack_split16(b)
        save_cold(f"split16_b{b}_weights", f"split16_b{b}_weights.fp16.bin", w, index)
        save_cold(f"split16_b{b}_aux", "split16_aux.bin", aux, index)
    for b in PROFILE["vit_blocks"]:
        w, scales = pack_vit(b)
        prefix = f"vit_block{b}" if args.profile == "vk102" else f"vit_b{b}"
        save_cold(prefix + "_weights", "vit_weights.fp16.bin", w, index)
        save_cold(prefix + "_scales", "vit_scales.fp32.bin", scales, index)
    post = PROFILE["post_block"]
    blend = (EXTRACTED / "inventory" / "weights" / f"block{post}.layer0.blend_scale.bin").read_bytes()
    assert len(blend) == 2
    save_cold(f"ioport_{post}_ioport_blend_scale", "ioport_blend_scale.fp16.bin", blend + bytes(2), index)

    manifest_dir = args.manifest.resolve()
    manifest_dir.mkdir(parents=True, exist_ok=True)
    index_path = manifest_dir / "cold_resources_index.json"
    index_path.write_text(json.dumps(index, indent=2), encoding="utf-8")
    print(f"ALL {len(index)} COLD RESOURCES PACKED AND INDEXED AT {index_path}")


if __name__ == "__main__":
    main()
