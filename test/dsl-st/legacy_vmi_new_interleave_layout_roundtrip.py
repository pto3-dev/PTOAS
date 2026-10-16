#!/usr/bin/env python3
# coding=utf-8
# Copyright (c) 2026 Huawei Technologies Co., Ltd.
# This program is free software, you can redistribute it and/or modify it under the terms and conditions of
# CANN Open Software License Agreement Version 2.0 (the "License").
# Please refer to the License for details. You may not use this file except in compliance with the License.
# THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
# INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
# See LICENSE in the root of the software repository for the full text of the License.
"""Migrated from test/vpto/cases/vmi_new/interleave-layout-roundtrip."""

import os
import sys
import tempfile
from pathlib import Path

import numpy as np

from common import auto_main
from ptodsl import pto

KERNEL_SOURCE = (
    '// Copyright (c) 2026 Huawei Technologies Co., Ltd.\n// This program is free software, you can redistribute '
    'it and/or modify it under the terms and conditions of\n// CANN Open Software License Agreement Version 2.0 ('
    'the "License").\n// Please refer to the License for details. You may not use this file except in compliance '
    'with the License.\n// THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER '
    'EXPRESS OR IMPLIED,\n// INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PAR'
    'TICULAR PURPOSE.\n// See LICENSE in the root of the software repository for the full text of the License.\n'
    '\nmodule attributes {pto.target_arch = "a5", pto.kernel_kind = #pto.kernel_kind<vector>} {\n  func.func @vmi'
    '_interleave_layout_roundtrip_kernel(\n      %lhs_gm: !pto.ptr<f16, gm>, %rhs_gm: !pto.ptr<f16, gm>,\n      %'
    'intlv_low_gm: !pto.ptr<f32, gm>, %intlv_high_gm: !pto.ptr<f32, gm>,\n      %roundtrip_low_gm: !pto.ptr<f32, '
    'gm>,\n      %roundtrip_high_gm: !pto.ptr<f32, gm>,\n      %dense_lhs_gm: !pto.ptr<f32, gm>, %dense_rhs_gm: !'
    'pto.ptr<f32, gm>,\n      %dense_roundtrip_low_gm: !pto.ptr<f32, gm>,\n      %dense_roundtrip_high_gm: !pto.p'
    'tr<f32, gm>) attributes {pto.kernel} {\n    %c0 = arith.constant 0 : index\n    %c0_i64 = arith.constant 0 :'
    ' i64\n    %c1_i64 = arith.constant 1 : i64\n    %c512_i64 = arith.constant 512 : i64\n    %c1024_i64 = arith'
    '.constant 1024 : i64\n    %c4096_i64 = arith.constant 4096 : i64\n    %c8192_i64 = arith.constant 8192 : i64'
    '\n    %c12288_i64 = arith.constant 12288 : i64\n    %c16384_i64 = arith.constant 16384 : i64\n    %c20480_i6'
    '4 = arith.constant 20480 : i64\n    %c24576_i64 = arith.constant 24576 : i64\n    %c28672_i64 = arith.consta'
    'nt 28672 : i64\n    %c32768_i64 = arith.constant 32768 : i64\n    %c36864_i64 = arith.constant 36864 : i64\n'
    '    %c40960_i64 = arith.constant 40960 : i64\n    %c45056_i64 = arith.constant 45056 : i64\n\n    %ub_lhs = '
    'pto.castptr %c0_i64 : i64 -> !pto.ptr<f16, ub>\n    %ub_rhs = pto.castptr %c4096_i64 : i64 -> !pto.ptr<f16, '
    'ub>\n    %ub_intlv_low = pto.castptr %c8192_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_intlv_high = pto.castptr'
    ' %c12288_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_roundtrip_low = pto.castptr %c16384_i64 : i64 -> !pto.ptr<f'
    '32, ub>\n    %ub_roundtrip_high = pto.castptr %c20480_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_dense_lhs = pt'
    'o.castptr %c24576_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_dense_rhs = pto.castptr %c28672_i64 : i64 -> !pto.'
    'ptr<f32, ub>\n    %ub_dense_intlv_low = pto.castptr %c32768_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_dense_in'
    'tlv_high = pto.castptr %c36864_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_dense_roundtrip_low = pto.castptr %c4'
    '0960_i64 : i64 -> !pto.ptr<f32, ub>\n    %ub_dense_roundtrip_high = pto.castptr %c45056_i64 : i64 -> !pto.pt'
    'r<f32, ub>\n\n    pto.mte_gm_ub %lhs_gm, %ub_lhs, %c0_i64, %c512_i64\n      nburst(%c1_i64, %c512_i64, %c512'
    '_i64)\n      : !pto.ptr<f16, gm>, !pto.ptr<f16, ub>, i64, i64, i64, i64, i64\n    pto.mte_gm_ub %rhs_gm, %ub'
    '_rhs, %c0_i64, %c512_i64\n      nburst(%c1_i64, %c512_i64, %c512_i64)\n      : !pto.ptr<f16, gm>, !pto.ptr<f'
    '16, ub>, i64, i64, i64, i64, i64\n    pto.mte_gm_ub %dense_lhs_gm, %ub_dense_lhs, %c0_i64, %c512_i64\n      '
    'nburst(%c1_i64, %c512_i64, %c512_i64)\n      : !pto.ptr<f32, gm>, !pto.ptr<f32, ub>, i64, i64, i64, i64, i64'
    '\n    pto.mte_gm_ub %dense_rhs_gm, %ub_dense_rhs, %c0_i64, %c512_i64\n      nburst(%c1_i64, %c512_i64, %c512'
    '_i64)\n      : !pto.ptr<f32, gm>, !pto.ptr<f32, ub>, i64, i64, i64, i64, i64\n\n    pto.set_flag["PIPE_MTE2"'
    ', "PIPE_V", "EVENT_ID0"]\n    pto.wait_flag["PIPE_MTE2", "PIPE_V", "EVENT_ID0"]\n\n    pto.vecscope {\n     '
    ' %lhs_f16 = pto.vmi.vload %ub_lhs[%c0]\n          : !pto.ptr<f16, ub> -> !pto.vmi.vreg<256xf16>\n      %rhs_'
    'f16 = pto.vmi.vload %ub_rhs[%c0]\n          : !pto.ptr<f16, ub> -> !pto.vmi.vreg<256xf16>\n      %lhs = pto.'
    'vmi.vcvt %lhs_f16\n          : !pto.vmi.vreg<256xf16> -> !pto.vmi.vreg<256xf32>\n      %rhs = pto.vmi.vcvt %'
    'rhs_f16\n          : !pto.vmi.vreg<256xf16> -> !pto.vmi.vreg<256xf32>\n      %mask_d2 = pto.vmi.pset "PAT_AL'
    'L" : !pto.vmi.mask<256xpred>\n      %intlv_low, %intlv_high = pto.vmi.vintlv %lhs, %rhs, %mask_d2\n         '
    ' : !pto.vmi.vreg<256xf32>, !pto.vmi.vreg<256xf32>,\n            !pto.vmi.mask<256xpred>\n          -> !pto.v'
    'mi.vreg<256xf32>, !pto.vmi.vreg<256xf32>\n      pto.vmi.vstore %intlv_low, %ub_intlv_low[%c0]\n          : !'
    'pto.vmi.vreg<256xf32>, !pto.ptr<f32, ub>\n      pto.vmi.vstore %intlv_high, %ub_intlv_high[%c0]\n          :'
    ' !pto.vmi.vreg<256xf32>, !pto.ptr<f32, ub>\n\n      %mask_d4 = pto.vmi.pset "PAT_ALL" : !pto.vmi.mask<256xpr'
    'ed>\n      %roundtrip_low, %roundtrip_high =\n          pto.vmi.vdintlv %intlv_low, %intlv_high, %mask_d4\n '
    '         : !pto.vmi.vreg<256xf32>, !pto.vmi.vreg<256xf32>,\n            !pto.vmi.mask<256xpred>\n          -'
    '> !pto.vmi.vreg<256xf32>, !pto.vmi.vreg<256xf32>\n      pto.vmi.vstore %roundtrip_low, %ub_roundtrip_low[%c0'
    ']\n          : !pto.vmi.vreg<256xf32>, !pto.ptr<f32, ub>\n      pto.vmi.vstore %roundtrip_high, %ub_roundtri'
    'p_high[%c0]\n          : !pto.vmi.vreg<256xf32>, !pto.ptr<f32, ub>\n\n      %dense_lhs = pto.vmi.vload %ub_d'
    'ense_lhs[%c0]\n          : !pto.ptr<f32, ub> -> !pto.vmi.vreg<128xf32>\n      %dense_rhs = pto.vmi.vload %ub'
    '_dense_rhs[%c0]\n          : !pto.ptr<f32, ub> -> !pto.vmi.vreg<128xf32>\n      %dense_mask = pto.vmi.pset "'
    'PAT_ALL" : !pto.vmi.mask<128xpred>\n      %dense_intlv_low, %dense_intlv_high =\n          pto.vmi.vintlv %d'
    'ense_lhs, %dense_rhs, %dense_mask\n          : !pto.vmi.vreg<128xf32>, !pto.vmi.vreg<128xf32>,\n            '
    '!pto.vmi.mask<128xpred>\n          -> !pto.vmi.vreg<128xf32>, !pto.vmi.vreg<128xf32>\n      pto.vmi.vstore %'
    'dense_intlv_low, %ub_dense_intlv_low[%c0]\n          : !pto.vmi.vreg<128xf32>, !pto.ptr<f32, ub>\n      pto.'
    'vmi.vstore %dense_intlv_high, %ub_dense_intlv_high[%c0]\n          : !pto.vmi.vreg<128xf32>, !pto.ptr<f32, u'
    'b>\n      %dense_roundtrip_low, %dense_roundtrip_high =\n          pto.vmi.vdintlv %dense_intlv_low, %dense_'
    'intlv_high, %dense_mask\n          : !pto.vmi.vreg<128xf32>, !pto.vmi.vreg<128xf32>,\n            !pto.vmi.m'
    'ask<128xpred>\n          -> !pto.vmi.vreg<128xf32>, !pto.vmi.vreg<128xf32>\n      pto.vmi.vstore %dense_roun'
    'dtrip_low, %ub_dense_roundtrip_low[%c0]\n          : !pto.vmi.vreg<128xf32>, !pto.ptr<f32, ub>\n      pto.vm'
    'i.vstore %dense_roundtrip_high, %ub_dense_roundtrip_high[%c0]\n          : !pto.vmi.vreg<128xf32>, !pto.ptr<'
    'f32, ub>\n    }\n\n    pto.set_flag["PIPE_V", "PIPE_MTE3", "EVENT_ID0"]\n    pto.wait_flag["PIPE_V", "PIPE_M'
    'TE3", "EVENT_ID0"]\n    pto.mte_ub_gm %ub_intlv_low, %intlv_low_gm, %c1024_i64\n      nburst(%c1_i64, %c1024'
    '_i64, %c1024_i64)\n      : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.mte_ub_gm %ub_i'
    'ntlv_high, %intlv_high_gm, %c1024_i64\n      nburst(%c1_i64, %c1024_i64, %c1024_i64)\n      : !pto.ptr<f32, '
    'ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.mte_ub_gm %ub_roundtrip_low, %roundtrip_low_gm, %c1024_i'
    '64\n      nburst(%c1_i64, %c1024_i64, %c1024_i64)\n      : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i'
    '64, i64\n    pto.mte_ub_gm %ub_roundtrip_high, %roundtrip_high_gm, %c1024_i64\n      nburst(%c1_i64, %c1024_'
    'i64, %c1024_i64)\n      : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.mte_ub_gm %ub_de'
    'nse_intlv_low, %dense_lhs_gm, %c512_i64\n      nburst(%c1_i64, %c512_i64, %c512_i64)\n      : !pto.ptr<f32, '
    'ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.mte_ub_gm %ub_dense_intlv_high, %dense_rhs_gm, %c512_i64'
    '\n      nburst(%c1_i64, %c512_i64, %c512_i64)\n      : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i64, '
    'i64\n    pto.mte_ub_gm %ub_dense_roundtrip_low, %dense_roundtrip_low_gm, %c512_i64\n      nburst(%c1_i64, %c'
    '512_i64, %c512_i64)\n      : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.mte_ub_gm %ub'
    '_dense_roundtrip_high, %dense_roundtrip_high_gm, %c512_i64\n      nburst(%c1_i64, %c512_i64, %c512_i64)\n   '
    '   : !pto.ptr<f32, ub>, !pto.ptr<f32, gm>, i64, i64, i64, i64\n    pto.barrier #pto.pipe<PIPE_ALL>\n    retu'
    'rn\n  }\n}\n'
)

def _golden_scope():
    _files = {}

    output_dir = None

    # Copyright (c) 2026 Huawei Technologies Co., Ltd.
    # This program is free software, you can redistribute it and/or modify it under the terms and conditions of
    # CANN Open Software License Agreement Version 2.0 (the "License").
    # Please refer to the License for details. You may not use this file except in compliance with the License.
    # THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
    # INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
    # See LICENSE in the root of the software repository for the full text of the License.

    import argparse
    from pathlib import Path

    import numpy as np

    WIDE_ELEMS = 256
    DENSE_ELEMS = 128
    SEED = 43
    SENTINEL = np.float32(-1777.0)


    def vintlv(lhs: np.ndarray, rhs: np.ndarray) -> tuple[np.ndarray, np.ndarray]:
        half = lhs.size // 2
        low = np.empty_like(lhs)
        high = np.empty_like(lhs)
        low[0::2] = lhs[:half]
        low[1::2] = rhs[:half]
        high[0::2] = lhs[half:]
        high[1::2] = rhs[half:]
        return low, high


    def _generate(seed: int) -> dict:
        rng = np.random.default_rng(seed)
        lhs_f16 = rng.uniform(-100.0, 100.0, size=WIDE_ELEMS).astype(np.float16)
        rhs_f16 = rng.uniform(200.0, 400.0, size=WIDE_ELEMS).astype(np.float16)
        lhs = lhs_f16.astype(np.float32)
        rhs = rhs_f16.astype(np.float32)
        intlv_low, intlv_high = vintlv(lhs, rhs)
        wide_empty = np.full(WIDE_ELEMS, SENTINEL, dtype=np.float32)
        dense_lhs = rng.uniform(500.0, 700.0, size=DENSE_ELEMS).astype(np.float32)
        dense_rhs = rng.uniform(-700.0, -500.0, size=DENSE_ELEMS).astype(np.float32)
        dense_intlv_low, dense_intlv_high = vintlv(dense_lhs, dense_rhs)
        dense_empty = np.full(DENSE_ELEMS, SENTINEL, dtype=np.float32)

        _files["v1.bin"] = lhs_f16
        _files["v2.bin"] = rhs_f16
        for index in range(3, 7):
            _files[f"v{index}.bin"] = wide_empty
        _files["v7.bin"] = dense_lhs
        _files["v8.bin"] = dense_rhs
        _files["v9.bin"] = dense_empty
        _files["v10.bin"] = dense_empty
        _files["golden_v3.bin"] = intlv_low
        _files["golden_v4.bin"] = intlv_high
        _files["golden_v5.bin"] = lhs
        _files["golden_v6.bin"] = rhs
        _files["golden_v7.bin"] = dense_intlv_low
        _files["golden_v8.bin"] = dense_intlv_high
        _files["golden_v9.bin"] = dense_lhs
        _files["golden_v10.bin"] = dense_rhs


    def main() -> None:
        parser = argparse.ArgumentParser()
        parser.add_argument("--output-dir", type=Path, default=Path("."))
        parser.add_argument("--seed", type=int, default=SEED)
        args = parser.parse_args()
        generate(args.output_dir, args.seed)


    return locals()

def _compare_scope():
    # Copyright (c) 2026 Huawei Technologies Co., Ltd.
    # This program is free software, you can redistribute it and/or modify it under the terms and conditions of
    # CANN Open Software License Agreement Version 2.0 (the "License").
    # Please refer to the License for details. You may not use this file except in compliance with the License.
    # THIS SOFTWARE IS PROVIDED ON AN "AS IS" BASIS, WITHOUT WARRANTIES OF ANY KIND, EITHER EXPRESS OR IMPLIED,
    # INCLUDING BUT NOT LIMITED TO NON-INFRINGEMENT, MERCHANTABILITY, OR FITNESS FOR A PARTICULAR PURPOSE.
    # See LICENSE in the root of the software repository for the full text of the License.

    import sys

    import numpy as np


    def main() -> None:
        for name in ("v3", "v4", "v5", "v6", "v7", "v8", "v9", "v10"):
            golden = np.fromfile(f"golden_{name}.bin", dtype=np.float32)
            output = np.fromfile(f"{name}.bin", dtype=np.float32)
            if golden.shape != output.shape or not np.array_equal(golden, output):
                diff = np.nonzero(golden != output)[0]
                idx = int(diff[0]) if diff.size else -1
                print(
                    f"[ERROR] compare failed {name} idx={idx} "
                    f"golden={golden[idx] if idx >= 0 else 'n/a'} "
                    f"output={output[idx] if idx >= 0 else 'n/a'}"
                )
                sys.exit(2)
        print("[INFO] compare passed")


    return locals()

HELPERS = {}
SEED_EXPR = 'SEED'
COMPARE_PAIRS = []

NUMPY_DTYPE = {
    'i8': 'int8',
    'i16': 'int16',
    'i32': 'int32',
    'i64': 'int64',
    'si8': 'int8',
    'si16': 'int16',
    'si32': 'int32',
    'si64': 'int64',
    'ui8': 'uint8',
    'ui16': 'uint16',
    'ui32': 'uint32',
    'ui64': 'uint64',
    'f16': 'float16',
    'f32': 'float32',
    'f64': 'float64',
    'bf16': 'uint16',
    'hif8': 'uint8',
    'f8E4M3FN': 'uint8',
    'f8E5M2': 'uint8',
    'f8e4m3': 'uint8',
    'f8e5m2': 'uint8',
    'f8e8m0': 'uint8',
    'f8E8M0FNU': 'uint8',
    'f4E2M1x2': 'uint8',
    'f4E1M2x2': 'uint8',
    'hif8x2': 'uint16',
    'f8e4m3x2': 'uint16',
    'f8e5m2x2': 'uint16',
    'f8e4m3x4': 'uint32',
    'f8e4m3x8': 'uint64',
    'f8e5m2x4': 'uint32',
    'f8e5m2x8': 'uint64',
    'f16x2': 'uint32',
    'bf16x2': 'uint32',
    'i8x2': 'uint16',
    'i16x2': 'uint32',
    'i32x2': 'uint64',
    'f32x2': 'uint64'
}


def _as_buffer_array(value, numpy_dtype):
    """Match a golden array to the raw bytes a kernel element type expects.

    A golden may build its array with ml_dtypes types (bfloat16) while the
    kernel argument is a plain numpy type (uint16); torch.from_numpy rejects
    the former, so reinterpret the bytes when the element widths agree.
    """
    array = np.asarray(value)
    want = np.dtype(numpy_dtype)
    if array.dtype == want:
        return array
    # The golden bytes are the device buffer; reinterpret them whenever the
    # byte count divides evenly so a narrow golden (for example uint8 init or
    # an f16 source) still fills the element type the kernel argument expects
    # instead of shrinking or doubling the buffer through astype.
    flat = np.ascontiguousarray(array).reshape(-1)
    if flat.nbytes % want.itemsize == 0:
        return flat.view(want)
    return array.astype(want)

BUFFERS = [
    (
        'v1',
        'f16',
        'lhs_gm'
    ),
    (
        'v2',
        'f16',
        'rhs_gm'
    ),
    (
        'v3',
        'f32',
        'intlv_low_gm'
    ),
    (
        'v4',
        'f32',
        'intlv_high_gm'
    ),
    (
        'v5',
        'f32',
        'roundtrip_low_gm'
    ),
    (
        'v6',
        'f32',
        'roundtrip_high_gm'
    ),
    (
        'v7',
        'f32',
        'dense_lhs_gm'
    ),
    (
        'v8',
        'f32',
        'dense_rhs_gm'
    ),
    (
        'v9',
        'f32',
        'dense_roundtrip_low_gm'
    ),
    (
        'v10',
        'f32',
        'dense_roundtrip_high_gm'
    )
]
SCALARS = []
SCALAR_SOURCES = []
SCALAR_DTYPES = []


@pto.jit(
    name='vmi_interleave_layout_roundtrip_kernel',
    target="a5",
    backend="vpto",
    mode="explicit",
    source=KERNEL_SOURCE,
)
def kernel(
    lhs_gm: pto.ptr(pto.f16, "gm"),
    rhs_gm: pto.ptr(pto.f16, "gm"),
    intlv_low_gm: pto.ptr(pto.f32, "gm"),
    intlv_high_gm: pto.ptr(pto.f32, "gm"),
    roundtrip_low_gm: pto.ptr(pto.f32, "gm"),
    roundtrip_high_gm: pto.ptr(pto.f32, "gm"),
    dense_lhs_gm: pto.ptr(pto.f32, "gm"),
    dense_rhs_gm: pto.ptr(pto.f32, "gm"),
    dense_roundtrip_low_gm: pto.ptr(pto.f32, "gm"),
    dense_roundtrip_high_gm: pto.ptr(pto.f32, "gm"),
):
    pass


class _TrackedArray(np.ndarray):
    """An array that records the positions written through __setitem__."""

    def __new__(cls, array):
        obj = np.asarray(array).view(cls)
        obj._write_mask = np.zeros(obj.shape, dtype=bool)
        return obj

    def __array_finalize__(self, source):
        if source is None:
            return
        self._write_mask = getattr(source, "_write_mask", None)

    def __setitem__(self, key, value):
        super().__setitem__(key, value)
        mask = getattr(self, "_write_mask", None)
        if mask is None or mask.shape != self.shape:
            mask = np.zeros(self.shape, dtype=bool)
            self._write_mask = mask
        mask[key] = True


def _materialize():
    """Run the case's own golden generator in memory; no .bin files.

    The golden's output buffers are created through the numpy constructors and
    then filled in place, so wrapping those constructors records exactly which
    positions the golden defines; the rest are don't care for the compare.
    """
    trackers = {name: getattr(np, name) for name in ("zeros", "full", "empty", "ones")}

    building = [False]

    def _track(name):
        original = trackers[name]

        def wrapped(*args, **kwargs):
            if building[0]:
                return original(*args, **kwargs)
            building[0] = True
            try:
                tracked = _TrackedArray(original(*args, **kwargs))
                if name != "empty":
                    # zeros/full/ones initialize every element, so the whole
                    # buffer is defined and compared; only np.empty leaves
                    # elements undefined, where the __setitem__ trace defines
                    # the valid mask.
                    tracked._write_mask = np.ones(tracked.shape, dtype=bool)
                return tracked
            finally:
                building[0] = False

        return wrapped

    for name in trackers:
        setattr(np, name, _track(name))
    try:
        namespace = _golden_scope()
        if "_generate" in namespace:
            seed = namespace[SEED_EXPR] if SEED_EXPR else 0
            namespace["_generate"](seed)
        else:
            sys.argv = ["golden.py"]
            namespace["main"]()
    finally:
        for name, original in trackers.items():
            setattr(np, name, original)
    produced = namespace["_files"]
    masks = {}
    for key, value in produced.items():
        if not key.startswith("golden_"):
            continue
        mask = getattr(value, "_write_mask", None)
        if mask is not None and np.asarray(mask).size and bool(np.asarray(mask).any()):
            masks[key] = np.asarray(mask).reshape(-1).copy()
        else:
            # a computed output defines every element; there is no partial
            # in-place write to record, so the whole file is compared.
            masks[key] = np.ones(np.asarray(value).size, dtype=bool)
    if masks:
        produced["@write_mask"] = masks
    return produced


def _apply_write_masks(files, produced):
    """Restrict each golden/output comparison to the golden's written set."""
    masks = produced.get("@write_mask") if hasattr(produced, "get") else None
    if not masks:
        return
    for golden_key, mask in masks.items():
        if not golden_key.startswith("golden_"):
            continue
        output_key = golden_key[len("golden_"):]
        if golden_key not in files or output_key not in files:
            continue
        golden = np.asarray(files[golden_key])
        output = np.asarray(files[output_key]).reshape(-1)
        flat = golden.reshape(-1)
        written = np.asarray(mask, dtype=bool).reshape(-1)
        size = min(flat.size, output.size, written.size)
        if size == 0 or not written[:size].any():
            continue
        adjusted = flat.copy()
        donotcare = ~written[:size]
        if output.dtype != flat.dtype and output.dtype.itemsize == flat.dtype.itemsize:
            # Same byte width but a different element type (for example the
            # kernel typed the buffer f16 while the golden built uint16): copy
            # the raw bytes so the donot-care fill stays bit-exact instead of
            # rounding through a numeric cast such as f16(-1.0) -> 0xffff.
            output = np.ascontiguousarray(output).view(flat.dtype)
        adjusted[:size][donotcare] = output[:size][donotcare]
        files[golden_key] = adjusted.reshape(golden.shape)


def _run_compare(files):
    """Run the case's own compare.py against in-memory arrays."""
    with tempfile.TemporaryDirectory(
            prefix="legacy-helpers-", dir=os.environ.get("TMPDIR")) as _helpers:
        _run_compare_in(files, Path(_helpers))


def _run_compare_in(files, helper_dir):
    for name, text in HELPERS.items():
        (helper_dir / name).write_text(text)

    real_fromfile, real_exists, real_argv = np.fromfile, os.path.exists, sys.argv
    real_exists_path = Path.exists
    real_environ, real_path = dict(os.environ), list(sys.path)

    def _fromfile(path, dtype=None, count=-1, offset=0, *args, **kwargs):
        name = os.path.basename(str(path))
        if name not in files:
            raise FileNotFoundError(name)
        # The legacy compare read the raw .bin bytes; reinterpret the stored
        # array's bytes instead of casting, so a deep-merged buffer written
        # through one element type still reads back as the type compare asks
        # for. count/offset mirror np.fromfile's element prefix semantics.
        array = np.asarray(files[name])
        data = array.tobytes()
        if offset:
            data = data[int(offset):]
        if dtype is None:
            dtype = array.dtype
        itemsize = np.dtype(dtype).itemsize
        available = len(data) // itemsize
        if count is None or int(count) < 0 or int(count) > available:
            count = available
        return np.frombuffer(data, dtype=dtype, count=count)

    np.fromfile = _fromfile
    os.path.exists = lambda p: os.path.basename(str(p)) in files or real_exists(p)
    Path.exists = lambda self: os.path.basename(str(self)) in files or real_exists_path(self)
    sys.argv = ["compare.py"]
    sys.path.insert(0, str(helper_dir))
    os.environ["COMPARE_STRICT"] = "1"
    try:
        namespace = _compare_scope()
        if "main" in namespace:
            namespace["main"]()
    except SystemExit as exc:
        if exc.code not in (0, None):
            raise AssertionError("compare.py exited with %r" % (exc.code,))
    finally:
        np.fromfile, os.path.exists, Path.exists, sys.argv = (
            real_fromfile, real_exists, real_exists_path, real_argv)
        os.environ.clear()
        os.environ.update(real_environ)
        sys.path[:] = real_path


def make_case():
    import torch
    produced = _materialize()
    output_to_golden = {out: gold for gold, out in COMPARE_PAIRS}
    arrays = []
    for name, ty, _slot in BUFFERS:
        if name.startswith("@same:"):
            arrays.append(np.asarray(produced["%s.bin" % name[len("@same:"):]]))
            continue
        if name.startswith("@scratch:"):
            arrays.append(np.empty_like(np.asarray(produced["%s.bin" % name[len("@scratch:"):]]),
                                        dtype=np.dtype(NUMPY_DTYPE[ty])))
            continue
        key = "%s.bin" % name
        if key in produced:
            arrays.append(_as_buffer_array(produced[key], NUMPY_DTYPE[ty]))
            continue
        golden_key = output_to_golden.get(key)
        if golden_key is None or golden_key not in produced:
            raise RuntimeError("golden did not produce %s" % key)
        arrays.append(np.zeros_like(np.asarray(produced[golden_key]),
                                    dtype=np.dtype(NUMPY_DTYPE[ty])))
    values = list(SCALARS)
    for _source, _ty in zip(SCALAR_SOURCES, SCALAR_DTYPES):
        _array = np.asarray(produced["%s.bin" % _source]).reshape(-1)
        values.append(float(_array[0]) if _ty == "f32" else int(_array[0]))
    if GRID_FROM_VALUES is not None:
        CASES[0]["grid"] = GRID_FROM_VALUES(values)
    return arrays, produced, values


def check_case(device_inputs, produced):
    if COMPARE_PAIRS:
        files = {gold: np.asarray(produced[gold]) for gold, _out in COMPARE_PAIRS if gold in produced}
    else:
        # no explicit pairs: the case compares whole files, so expose every
        # array the golden built (its .tofile names became dictionary keys).
        files = {name: np.asarray(value) for name, value in produced.items()
                 if not name.startswith("@")}
    if not files:
        raise AssertionError("golden.py produced no golden output")
    for _source in SCALAR_SOURCES:
        _key = "%s.bin" % _source
        if _key in produced:
            files[_key] = np.asarray(produced[_key])
    for (name, _ty, _slot), tensor in zip(BUFFERS, device_inputs):
        if not name.startswith("@"):
            files["%s.bin" % name] = tensor.cpu().numpy()
    _apply_write_masks(files, produced)
    _run_compare(files)


GRID_FROM_VALUES = None


CASES = [dict(
    name='legacy_vmi_new_interleave_layout_roundtrip',
    grid=1,
    kernel=kernel,
    make_case=make_case,
    check=check_case,
)]

auto_main(globals())
