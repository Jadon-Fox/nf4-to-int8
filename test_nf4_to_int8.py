#!/usr/bin/env python3
"""Golden checks. Codebook + roundtrip + pin. Not train_ok."""
from __future__ import annotations

import json
import subprocess
import sys
import tempfile
from pathlib import Path

from nf4 import (
    NF4_CODEBOOK,
    NIBBLE_LO_THEN_HI,
    decode_absmax_double,
    dequant_int8,
    dequant_nf4,
    max_abs_err,
    pack_f32,
    quantize_int8_symmetric,
    quantize_nf4,
    rmse,
)
from nf4_to_int8 import convert, demo_weights
from dtype_io import pack_bf16, unpack_bf16
from pin_convert import Policy, convert_pin
from safetensors_io import SafeTensorsFile, write_safetensors

ROOT = Path(__file__).resolve().parent


def test_codebook_ends():
    assert NF4_CODEBOOK[0] == -1.0
    assert NF4_CODEBOOK[7] == 0.0
    assert NF4_CODEBOOK[15] == 1.0
    assert len(NF4_CODEBOOK) == 16


def test_nf4_roundtrip_zero_and_scale():
    w = [0.0] * 64 + [0.5] * 64
    qw, am = quantize_nf4(w, blocksize=64)
    rec = dequant_nf4(qw, am, 128, 64, NIBBLE_LO_THEN_HI)
    assert am[0] == 0.0
    assert abs(am[1] - 0.5) < 1e-6
    assert max(abs(x) for x in rec[:64]) < 1e-12
    assert abs(rec[64] - 0.5) < 1e-6


def test_int8_zero_point_and_clip():
    w = [0.0, 1.0, -1.0, 2.0]
    q, s = quantize_int8_symmetric(w, blocksize=4)
    rec = dequant_int8(q, s, 4)
    assert s[0] == 2.0 / 127.0
    signed = [b if b < 128 else b - 256 for b in q]
    assert signed[0] == 0
    assert signed[3] == 127
    assert abs(rec[3] - 2.0) < 1e-6


def test_convert_rmse_small():
    w = demo_weights(256)
    qw, am = quantize_nf4(w, blocksize=64)
    got = convert(bytes(qw), am, 256, 64, NIBBLE_LO_THEN_HI, 64)
    assert got["meta"]["train_ok"] is False
    assert got["meta"]["rmse_vs_nf4_dequant"] < 0.02
    assert got["meta"]["max_abs_err_vs_nf4_dequant"] < 0.05
    assert rmse(got["f32"], got["recon"]) == got["meta"]["rmse_vs_nf4_dequant"]
    assert max_abs_err(got["f32"], got["recon"]) == got["meta"]["max_abs_err_vs_nf4_dequant"]


def test_cli_demo():
    with tempfile.TemporaryDirectory() as td:
        prefix = Path(td) / "w"
        r = subprocess.run(
            [sys.executable, str(ROOT / "nf4_to_int8.py"), "--demo", "--out-prefix", str(prefix), "--json"],
            check=True,
            capture_output=True,
            text=True,
        )
        meta = json.loads(r.stdout)
        assert meta["n_elem"] == 256
        assert (prefix.with_suffix(".i8.bin")).stat().st_size == 256
        assert (prefix.with_suffix(".scale.f32.bin")).stat().st_size == 4 * 4


def test_double_quant_offset():
    # 4 L1 blocks, nested_bs=4 so 1 nested scale
    nmap = [((i - 127) / 127.0) for i in range(256)]
    nmap[127] = 0.0
    codes = bytes([200, 180, 127, 90])
    nested = [0.04]
    off = 0.0855
    am = decode_absmax_double(codes, nmap, nested, off, nested_blocksize=4)
    assert len(am) == 4
    assert am[2] == off  # code 127 → 0 * scale + offset
    assert am[0] > am[3]


def _write_single_quant_module(path: Path, stem: str, w: list[float], out_f: int, in_f: int) -> None:
    qw, am = quantize_nf4(w, blocksize=64)
    state = json.dumps(
        {
            "quant_type": "nf4",
            "blocksize": 64,
            "dtype": "bfloat16",
            "shape": [out_f, in_f],
            "nested_blocksize": 256,
            "nested_dtype": "float32",
            "nested_offset": 0.0,
        },
        separators=(",", ":"),
    ).encode()
    tensors = [
        (stem + ".weight", "U8", (len(qw), 1), bytes(qw)),
        (stem + ".weight.absmax", "F32", (len(am),), pack_f32(am)),
        (stem + ".weight.quant_map", "F32", (16,), pack_f32(list(NF4_CODEBOOK))),
        (stem + ".weight.quant_state.bitsandbytes__nf4", "U8", (len(state),), state),
    ]
    # BF16-looking passthrough (raw 2 bytes × 4)
    tensors.append(("model.norm.weight", "BF16", (4,), b"\x00\x3c" * 4))
    write_safetensors(str(path), tensors, metadata={"format": "pt"})


def test_pin_single_quant_roundtrip():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "src"
        src.mkdir()
        _write_single_quant_module(src / "model.safetensors", "model.layers.0.mlp.down_proj", w, out_f, in_f)
        (src / "config.json").write_text(json.dumps({"model_type": "phi3", "hidden_size": 8}) + "\n")
        dst = Path(td) / "pin"
        got = convert_pin(src, dst, int8_blocksize=64, policy=Policy(allow_requant=True))
        pin = got["pin"]
        assert pin["train_ok"] is False
        assert pin["n_nf4_modules"] == 1
        assert pin["n_passthrough"] == 1
        assert pin["rmse_mean"] < 0.02
        assert (dst / "model.safetensors").is_file()
        assert (dst / "pin.json").is_file()
        with SafeTensorsFile(str(dst / "model.safetensors")) as st:
            assert st.tensors["model.layers.0.mlp.down_proj.weight"].dtype == "I8"
            assert st.tensors["model.layers.0.mlp.down_proj.weight"].shape == (8, 64)
            assert "model.norm.weight" in st.tensors
            assert st.tensors["model.norm.weight"].dtype == "BF16"
            assert "model.layers.0.mlp.down_proj.weight.absmax" not in st.tensors
        cfg = json.loads((dst / "config.json").read_text())
        assert cfg["quantization_config"]["quant_method"] == "nf4_to_int8_pin"


def test_cli_pin_dry_run():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "model.safetensors"
        _write_single_quant_module(src, "lin", w, out_f, in_f)
        r = subprocess.run(
            [
                sys.executable,
                str(ROOT / "nf4_to_int8.py"),
                "pin",
                "--src",
                str(src),
                "--out",
                str(Path(td) / "unused"),
                "--dry-run",
                "--allow-requant",
            ],
            check=True,
            capture_output=True,
            text=True,
        )
        plan = json.loads(r.stdout)
        assert plan["n_nf4_modules"] == 1
        assert "lin" in plan["nf4_modules"]


def test_fixture_cli():
    with tempfile.TemporaryDirectory() as td:
        r = subprocess.run(
            [sys.executable, str(ROOT / "nf4_to_int8.py"), "fixture", "--out", td],
            check=True,
            capture_output=True,
            text=True,
        )
        pin = json.loads(r.stdout)
        assert pin["schema"] == "nf4_to_int8_pin_v1"
        assert pin["train_ok"] is False
        assert (Path(td) / "int8_pin" / "model.safetensors").is_file()
        assert (Path(td) / "int8_pin" / "pin.json").is_file()


def test_double_quant_module_pin():
    # encode L1 absmax through a fake 256-map so D1 decode is exact enough
    out_f, in_f = 4, 64
    w = demo_weights(out_f * in_f)
    qw, am = quantize_nf4(w, blocksize=64)
    nmap = [((i - 127) / 127.0) for i in range(256)]
    nmap[127] = 0.0
    offset = 0.08
    # pick codes + nested so decode ≈ am (am is small positive)
    # am_fp = nmap[c] * nested + offset  →  nmap[c] = (am - offset) / nested
    nested_val = 0.05
    codes = bytearray()
    for a in am:
        target = (a - offset) / nested_val
        best = min(range(256), key=lambda i: abs(nmap[i] - target))
        codes.append(best)
    state = json.dumps(
        {
            "quant_type": "nf4",
            "blocksize": 64,
            "dtype": "bfloat16",
            "shape": [out_f, in_f],
            "nested_blocksize": 256,
            "nested_dtype": "float32",
            "nested_offset": offset,
        },
        separators=(",", ":"),
    ).encode()
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "model.safetensors"
        write_safetensors(
            str(src),
            [
                ("lin.weight", "U8", (len(qw), 1), bytes(qw)),
                ("lin.weight.absmax", "U8", (len(codes),), bytes(codes)),
                ("lin.weight.nested_absmax", "F32", (1,), pack_f32([nested_val])),
                ("lin.weight.nested_quant_map", "F32", (256,), pack_f32(nmap)),
                ("lin.weight.quant_map", "F32", (16,), pack_f32(list(NF4_CODEBOOK))),
                ("lin.weight.quant_state.bitsandbytes__nf4", "U8", (len(state),), state),
            ],
        )
        dst = Path(td) / "pin"
        got = convert_pin(src, dst, policy=Policy(allow_requant=True))
        assert got["pin"]["n_nf4_modules"] == 1
        assert got["modules"][0]["double_quant"] == "double"
        assert got["pin"]["train_ok"] is False


def test_bf16_roundtrip_bits():
    vals = [0.0, 1.0, -0.5, 0.25]
    rec = unpack_bf16(pack_bf16(vals))
    for a, b in zip(vals, rec):
        assert abs(a - b) < 1e-2


def test_dense_bf16_pin():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "src"
        src.mkdir()
        write_safetensors(
            str(src / "model.safetensors"),
            [
                ("model.layers.0.mlp.down_proj.weight", "BF16", (out_f, in_f), pack_bf16(w)),
                ("model.layers.0.mlp.gate_up_proj.weight", "BF16", (out_f, in_f), pack_bf16(w)),
                ("model.embed_tokens.weight", "BF16", (32, in_f), pack_bf16(demo_weights(32 * in_f))),
                ("model.norm.weight", "BF16", (8,), pack_bf16([1.0] * 8)),
            ],
        )
        (src / "config.json").write_text(json.dumps({"model_type": "phi3"}) + "\n")
        dst = Path(td) / "pin"
        got = convert_pin(src, dst, policy=Policy(dense="int8", embed="copy"))
        pin = got["pin"]
        assert pin["n_dense_modules"] == 2
        assert pin["n_nf4_modules"] == 0
        assert "bf16" in pin["src_kinds"]
        with SafeTensorsFile(str(dst / "model.safetensors")) as st:
            assert st.tensors["model.layers.0.mlp.down_proj.weight"].dtype == "I8"
            assert st.tensors["model.embed_tokens.weight"].dtype == "BF16"
            assert st.tensors["model.norm.weight"].dtype == "BF16"


def test_dense_copy_policy():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "model.safetensors"
        write_safetensors(
            str(src),
            [("lin.weight", "BF16", (out_f, in_f), pack_bf16(w))],
        )
        dst = Path(td) / "pin"
        got = convert_pin(src, dst, policy=Policy(dense="copy"))
        with SafeTensorsFile(str(dst / "model.safetensors")) as st:
            assert st.tensors["lin.weight"].dtype == "BF16"
        assert got["pin"]["n_dense_modules"] == 0


def test_refuse_gptq():
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "model.safetensors"
        write_safetensors(
            str(src),
            [
                ("lin.qweight", "I32", (8,), b"\x00" * 32),
                ("lin.qzeros", "I32", (2,), b"\x00" * 8),
            ],
        )
        try:
            convert_pin(src, Path(td) / "pin")
        except ValueError as e:
            assert "HARD_BLOCK" in str(e)
        else:
            raise AssertionError("expected GPTQ refuse")


def test_refuse_nf4_without_allow_requant():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "model.safetensors"
        _write_single_quant_module(src, "lin", w, out_f, in_f)
        try:
            convert_pin(src, Path(td) / "pin")
        except ValueError as e:
            assert "already NF4" in str(e)
        else:
            raise AssertionError("expected NF4 refuse")


def test_bf16_to_nf4_pin():
    out_f, in_f = 8, 64
    w = demo_weights(out_f * in_f)
    with tempfile.TemporaryDirectory() as td:
        src = Path(td) / "src"
        src.mkdir()
        write_safetensors(
            str(src / "model.safetensors"),
            [
                ("lin.weight", "BF16", (out_f, in_f), pack_bf16(w)),
                ("model.norm.weight", "BF16", (8,), pack_bf16([1.0] * 8)),
            ],
        )
        dst = Path(td) / "pin"
        got = convert_pin(src, dst, policy=Policy(dest="nf4", dense="quantize"))
        pin = got["pin"]
        assert pin["schema"] == "bf16_to_nf4_pin_v1"
        assert pin["dest"] == "nf4"
        assert pin["n_converted"] == 1
        with SafeTensorsFile(str(dst / "model.safetensors")) as st:
            assert st.tensors["lin.weight"].dtype == "U8"
            assert "lin.weight.absmax" in st.tensors
            assert st.tensors["model.norm.weight"].dtype == "BF16"


if __name__ == "__main__":
    test_codebook_ends()
    test_nf4_roundtrip_zero_and_scale()
    test_int8_zero_point_and_clip()
    test_convert_rmse_small()
    test_cli_demo()
    test_double_quant_offset()
    test_pin_single_quant_roundtrip()
    test_cli_pin_dry_run()
    test_fixture_cli()
    test_double_quant_module_pin()
    test_bf16_roundtrip_bits()
    test_dense_bf16_pin()
    test_dense_copy_policy()
    test_refuse_gptq()
    test_refuse_nf4_without_allow_requant()
    test_bf16_to_nf4_pin()
    print("TEST_NF4_TO_INT8_GREEN bf16_to_int8 bf16_to_nf4 refuse_requant NOT_train_ok")
