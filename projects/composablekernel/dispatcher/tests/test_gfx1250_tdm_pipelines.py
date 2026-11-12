#!/usr/bin/env python3

# Copyright (c) Advanced Micro Devices, Inc., or its affiliates.
# SPDX-License-Identifier: MIT

"""
CPU tests for the gfx1250 comp_async / comp_tdm / comp_tdm_v2 / comp_tdm_pc /
comp_tdm_ra pipelines and the
tdm epilogue in the dispatcher: arch filter rules, codegen type maps, LDS
budgets, generated kernel headers, the Python sweep gate and the C++ enums.

Run: python3 -m pytest tests/test_gfx1250_tdm_pipelines.py -v
"""

import json
import shutil
import subprocess
import sys
import tempfile
import unittest
from pathlib import Path

SCRIPT_DIR = Path(__file__).parent.resolve()
DISPATCHER_DIR = SCRIPT_DIR.parent
CODEGEN_DIR = DISPATCHER_DIR / "codegen"
INCLUDE_DIR = DISPATCHER_DIR / "include"
sys.path.insert(0, str(CODEGEN_DIR))
sys.path.insert(0, str(DISPATCHER_DIR / "python"))

from arch_filter import (  # noqa: E402
    TDM_PIPELINES,
    ArchFilter,
    KernelConfig,
    OperatorType,
    ValidationResult,
)
from arch_specs_generated import get_lds_limit  # noqa: E402
from codegen_common import (  # noqa: E402
    COMP_TDM_PC_WARP_K_REJECT_REASON,
    COMP_TDM_RA_BATCHED_REJECT_REASON,
    COMP_TDM_RA_WARP_K_REJECT_REASON,
    CommonTypeMappings,
    GFX1250_COMP_ASYNC_PAD_REJECT_REASON,
    comp_tdm_pc_acc_reject_reason,
    comp_tdm_pc_ring_reject_reason,
    comp_tdm_ra_ring_reject_reason,
    pipeline_ring_fields,
    pipeline_ring_lds_limit,
    pipeline_ring_param,
    pipeline_ring_reject_reason,
    pipeline_ring_suffix,
    preshuffle_pipeline_reject_reason,
    split_pipeline_ring,
    GFX1250_COMPV5_REJECT_REASON,
    GEMM_TDM_CSHUFFLE_PIPELINES,
    STREAMK_GFX1250_PIPELINES,
    gfx1250_comp_async_8bit_warp_tile_k_rejected,
    gfx1250_comp_async_8bit_warp_tile_mn_rejected,
    gfx1250_pipeline_reject_reason,
    streamk_trait_reject_reason,
    TDM_PAD_REJECT_REASON,
)

TE_GEMM_DIR = DISPATCHER_DIR.parent / "tile_engine" / "ops" / "gemm"
sys.path.insert(0, str(TE_GEMM_DIR))
try:
    import gemm_validation_utils as te  # noqa: E402
except ImportError:  # pragma: no cover - TE tree not present
    te = None

TDM_TILE = dict(
    tile_m=128,
    tile_n=128,
    tile_k=64,
    warp_m=2,
    warp_n=2,
    warp_k=1,
    warp_tile_m=16,
    warp_tile_n=16,
    warp_tile_k=32,
)


class TestArchFilter(unittest.TestCase):
    def _valid(self, arch, **kw):
        args = dict(TDM_TILE)
        args.update(kw)
        return ArchFilter(arch).is_kernel_valid(**args)

    def test_tdm_valid_on_gfx1250(self):
        for pipe in TDM_PIPELINES:
            self.assertTrue(self._valid("gfx1250", pipeline=pipe, epilogue="tdm"))

    def test_tdm_rejected_off_gfx1250(self):
        for arch in ("gfx942", "gfx950", "gfx90a"):
            for pipe in TDM_PIPELINES:
                self.assertFalse(
                    self._valid(arch, pipeline=pipe, epilogue="tdm"), (arch, pipe)
                )

    def test_tdm_v2_requires_four_waves(self):
        self.assertFalse(
            self._valid("gfx1250", pipeline="comp_tdm_v2", epilogue="tdm", warp_m=4)
        )
        self.assertTrue(
            self._valid("gfx1250", pipeline="comp_tdm", epilogue="tdm", warp_m=4)
        )

    def test_tdm_pipeline_epilogue_pairing(self):
        self.assertFalse(self._valid("gfx1250", pipeline="compv3", epilogue="tdm"))
        self.assertFalse(
            self._valid("gfx1250", pipeline="comp_tdm", epilogue="cshuffle")
        )

    def test_tdm_rejects_interwave(self):
        for pipe in TDM_PIPELINES:
            self.assertFalse(
                self._valid(
                    "gfx1250", pipeline=pipe, epilogue="tdm", scheduler="interwave"
                ),
                pipe,
            )

    def test_tdm_pc_accumulator_cap(self):
        # 256x256 over 4 waves needs 512 accumulator VGPRs per lane; 8 waves
        # bring it to the 256 cap. comp_tdm has no such rule.
        tile = dict(tile_m=256, tile_n=256, tile_k=32)
        pc = dict(pipeline="comp_tdm_pc", epilogue="tdm", **tile)
        self.assertFalse(self._valid("gfx1250", **pc))
        self.assertTrue(self._valid("gfx1250", warp_m=4, **pc))
        self.assertTrue(
            self._valid("gfx1250", pipeline="comp_tdm", epilogue="tdm", **tile)
        )
        self.assertIn("512 VGPRs per lane", comp_tdm_pc_acc_reject_reason(256, 256, 4))
        self.assertEqual(comp_tdm_pc_acc_reject_reason(256, 128, 4), "")
        self.assertNotEqual(comp_tdm_pc_acc_reject_reason(256, 128, 0), "")

    def test_tdm_pc_four_slot_lds(self):
        # fp16 256x128x128: A+B (with row padding) fits the 163840B
        # double-buffered comp_tdm budget but not the 81920B four-slot ring.
        tile = dict(tile_m=256, tile_n=128, tile_k=128, warp_m=4)
        self.assertTrue(
            self._valid("gfx1250", pipeline="comp_tdm", epilogue="tdm", **tile)
        )
        self.assertFalse(
            self._valid("gfx1250", pipeline="comp_tdm_pc", epilogue="tdm", **tile)
        )

    def test_tdm_pc_rejects_k_waves(self):
        # 1x2x2 makes four consumer waves, but BlockGemm and the epilogue spread
        # C over warp_m x warp_n only, with no K-wave reduction.
        pc = dict(pipeline="comp_tdm_pc", epilogue="tdm")
        self.assertFalse(self._valid("gfx1250", warp_m=1, warp_k=2, **pc))
        self.assertTrue(self._valid("gfx1250", **pc))
        self.assertEqual(
            gfx1250_pipeline_reject_reason(
                "gfx1250",
                "comp_tdm_pc",
                "tdm",
                "intrawave",
                4,
                32,
                "fp16",
                "fp16",
                "rcr",
                warp_k=2,
            ),
            COMP_TDM_PC_WARP_K_REJECT_REASON,
        )
        if te is None:
            self.skipTest("tile_engine gemm_validation_utils not importable")
        te_pc = ("fp16", "comp_tdm_pc", "gfx1250", "rcr")
        self.assertFalse(
            te.validate_gemm_gfx1250_pipeline(128, 128, 1, 2, 2, *te_pc)[0]
        )
        self.assertTrue(te.validate_gemm_gfx1250_pipeline(128, 128, 2, 2, 1, *te_pc)[0])

    def test_tdm_ra_has_no_accumulator_cap(self):
        # Every wave multiplies, and the pipeline is built for big per-wave C
        # tiles: 256x256 on 4 waves (512 accumulators per lane) is accepted,
        # unlike comp_tdm_pc.
        tile = dict(tile_m=256, tile_n=256, tile_k=32)
        self.assertTrue(
            self._valid("gfx1250", pipeline="comp_tdm_ra", epilogue="tdm", **tile)
        )
        self.assertFalse(
            self._valid("gfx1250", pipeline="comp_tdm_pc", epilogue="tdm", **tile)
        )

    def test_tdm_ra_rejects_k_waves(self):
        ra = dict(pipeline="comp_tdm_ra", epilogue="tdm")
        self.assertFalse(self._valid("gfx1250", warp_m=1, warp_k=2, **ra))
        self.assertTrue(self._valid("gfx1250", **ra))
        self.assertEqual(
            gfx1250_pipeline_reject_reason(
                "gfx1250",
                "comp_tdm_ra",
                "tdm",
                "intrawave",
                4,
                32,
                "fp16",
                "fp16",
                "rcr",
                warp_k=2,
            ),
            COMP_TDM_RA_WARP_K_REJECT_REASON,
        )

    def test_tdm_ra_four_slot_lds(self):
        # Same quarter-of-LDS slot budget as comp_tdm_pc for the default ring.
        tile = dict(tile_m=256, tile_n=128, tile_k=128, warp_m=4)
        self.assertFalse(
            self._valid("gfx1250", pipeline="comp_tdm_ra", epilogue="tdm", **tile)
        )

    def test_tdm_ra_operators(self):
        # Plain GEMM only: no preshuffle or Stream-K kernel (batched is the
        # codegen's batched flag, which this filter does not see).
        ra = dict(pipeline="comp_tdm_ra", epilogue="tdm")
        for op in (OperatorType.GEMM_PRESHUFFLE, OperatorType.GEMM_STREAMK):
            self.assertFalse(self._valid("gfx1250", operator=op, **ra), op)
        self.assertTrue(self._valid("gfx1250", operator=OperatorType.GEMM, **ra))

    def test_tdm_pc_transposed_lds_boundary(self):
        # fp16 192-deep tiles: the K-contiguous (rcr) descriptors need 76768B per
        # slot, under the 81920B four-slot budget. With crr both operands are
        # transpose-loaded; their MN-contiguous descriptors need 55264B (MN=128)
        # plus 27616B (MN=64) = 82880B per slot, 331520B for the ring, which
        # exceeds the 327680B LDS and does not compile.
        for tile_m, tile_n in ((64, 128), (128, 64)):
            tile = dict(tile_m=tile_m, tile_n=tile_n, tile_k=192)
            pc = dict(pipeline="comp_tdm_pc", epilogue="tdm", **tile)
            self.assertTrue(self._valid("gfx1250", layout="rcr", **pc), tile)
            self.assertFalse(self._valid("gfx1250", layout="crr", **pc), tile)
            if te is None:
                continue
            lds = dict(a_datatype="fp16", b_datatype="fp16", pipeline="comp_tdm_pc")
            lds.update(tile, gpu_target="gfx1250", gfx1250_gemm_pipeline=True)
            self.assertTrue(te.validate_lds_capacity(**lds, layout="rcr")[0], tile)
            self.assertFalse(te.validate_lds_capacity(**lds, layout="crr")[0], tile)

    def test_comp_async_not_gated_by_shared_filter(self):
        # grouped_conv uses comp_async on gfx950, so the shared arch filter must
        # not reject it; the GEMM gfx1250 gate lives in unified_gemm_codegen.
        self.assertTrue(
            self._valid(
                "gfx950",
                pipeline="comp_async",
                epilogue="cshuffle",
                warp_tile_m=32,
                warp_tile_n=32,
                warp_tile_k=16,
            )
        )

    def test_comp_async_pad_rule_gfx1250(self):
        # Opt-in: the rule only runs when all three pad traits are passed.
        self.assertTrue(self._valid("gfx1250", pipeline="comp_async"))
        self.assertTrue(
            self._valid(
                "gfx1250", pipeline="comp_async", pad_m=True, pad_n=True, pad_k=True
            )
        )
        for pads in ((False, False, False), (False, True, True), (True, True, False)):
            kw = dict(zip(("pad_m", "pad_n", "pad_k"), pads))
            self.assertFalse(self._valid("gfx1250", pipeline="comp_async", **kw), pads)
            self.assertTrue(self._valid("gfx1250", pipeline="compv3", **kw), pads)
        # gfx950 comp_async (grouped_conv, MX) is not pad-gated.
        self.assertTrue(
            self._valid(
                "gfx950",
                pipeline="comp_async",
                warp_tile_m=32,
                warp_tile_n=32,
                warp_tile_k=16,
                pad_m=False,
                pad_n=False,
                pad_k=False,
            )
        )

    def test_comp_async_8bit_warp_tile_k_rule_gfx1250(self):
        pads = dict(pad_m=True, pad_n=True, pad_k=True)
        for dt in ("fp8", "bf8"):
            kw = dict(datatype_a=dt, datatype_b=dt, datatype_c="fp16", tile_k=128)
            self.assertFalse(
                self._valid(
                    "gfx1250", pipeline="comp_async", warp_tile_k=64, **kw, **pads
                ),
                dt,
            )
            self.assertTrue(
                self._valid(
                    "gfx1250", pipeline="comp_async", warp_tile_k=128, **kw, **pads
                ),
                dt,
            )
            # Only comp_async is affected.
            self.assertTrue(
                self._valid("gfx1250", pipeline="compv3", warp_tile_k=64, **kw), dt
            )
        self.assertTrue(gfx1250_comp_async_8bit_warp_tile_k_rejected("fp8", "fp8", 64))
        self.assertTrue(gfx1250_comp_async_8bit_warp_tile_k_rejected("fp16", "bf8", 32))
        self.assertFalse(
            gfx1250_comp_async_8bit_warp_tile_k_rejected("bf8", "bf8", 128)
        )
        self.assertFalse(
            gfx1250_comp_async_8bit_warp_tile_k_rejected("fp16", "fp16", 32)
        )

    def test_comp_async_8bit_warp_tile_mn_rule_gfx1250(self):
        pads = dict(pad_m=True, pad_n=True, pad_k=True)
        wt32 = dict(warp_tile_m=32, warp_tile_n=32, warp_tile_k=128)
        for dt in ("fp8", "bf8"):
            kw = dict(datatype_a=dt, datatype_b=dt, datatype_c="fp16", tile_k=256)
            self.assertFalse(
                self._valid("gfx1250", pipeline="comp_async", **wt32, **kw, **pads),
                dt,
            )
            self.assertTrue(
                self._valid(
                    "gfx1250", pipeline="comp_async", warp_tile_k=128, **kw, **pads
                ),
                dt,
            )
            # Only comp_async is affected.
            self.assertTrue(self._valid("gfx1250", pipeline="compv3", **wt32, **kw), dt)
        self.assertTrue(
            gfx1250_comp_async_8bit_warp_tile_mn_rejected("fp8", "fp8", 32, 32)
        )
        self.assertTrue(
            gfx1250_comp_async_8bit_warp_tile_mn_rejected("fp16", "bf8", 32, 32)
        )
        self.assertFalse(
            gfx1250_comp_async_8bit_warp_tile_mn_rejected("bf8", "bf8", 16, 16)
        )
        self.assertFalse(
            gfx1250_comp_async_8bit_warp_tile_mn_rejected("fp16", "fp16", 32, 32)
        )

    def test_existing_pipelines_unchanged(self):
        for arch in ("gfx942", "gfx950"):
            self.assertTrue(
                self._valid(
                    arch,
                    pipeline="compv3",
                    epilogue="cshuffle",
                    warp_tile_m=32,
                    warp_tile_n=32,
                    warp_tile_k=16,
                )
            )


class TestArchFilterGfx1250Rejects(unittest.TestCase):
    """ArchFilter must reject every gfx1250 config the codegen, python/gemm_utils
    and the Tile Engine reject (codegen_common.gfx1250_pipeline_reject_reason is
    the shared rule set)."""

    PADS_TTT = dict(pad_m=True, pad_n=True, pad_k=True)
    PADS_FFF = dict(pad_m=False, pad_n=False, pad_k=False)

    def _valid(self, arch="gfx1250", **kw):
        args = dict(TDM_TILE)
        args.update(kw)
        return ArchFilter(arch).is_kernel_valid(**args)

    def test_tdm_rejects_any_pad(self):
        for pipe in TDM_PIPELINES:
            self.assertTrue(self._valid(pipeline=pipe, epilogue="tdm", **self.PADS_FFF))
            for name in ("pad_m", "pad_n", "pad_k"):
                pads = dict(self.PADS_FFF, **{name: True})
                self.assertFalse(
                    self._valid(pipeline=pipe, epilogue="tdm", **pads), (pipe, name)
                )
            self.assertFalse(
                self._valid(pipeline=pipe, epilogue="tdm", **self.PADS_TTT)
            )

    def test_tdm_scheduler_and_epilogue(self):
        if te is not None:
            self.assertEqual(
                GEMM_TDM_CSHUFFLE_PIPELINES, te.GEMM_TDM_CSHUFFLE_PIPELINES
            )
        for pipe in TDM_PIPELINES:
            for epi in ("cshuffle", "default"):
                # Plain GEMM also pairs comp_tdm_pc with cshuffle; spelled out so that
                # widening GEMM_TDM_CSHUFFLE_PIPELINES needs a test change.
                want = epi == "cshuffle" and pipe == "comp_tdm_pc"
                self.assertEqual(
                    self._valid(pipeline=pipe, epilogue=epi), want, (pipe, epi)
                )
            self.assertFalse(
                self._valid(pipeline=pipe, epilogue="tdm", scheduler="interwave")
            )
        # The tdm epilogue needs a TDM pipeline on every arch.
        for arch in ("gfx950", "gfx1250"):
            for pipe in ("comp_async", "compv3", "compv4", "mem"):
                self.assertFalse(
                    self._valid(arch, pipeline=pipe, epilogue="tdm"), (arch, pipe)
                )
        # The cshuffle pairing is plain GEMM only: preshuffle has no comp_tdm_pc kernel.
        self.assertFalse(
            self._valid(
                pipeline="comp_tdm_pc",
                epilogue="cshuffle",
                operator=OperatorType.GEMM_PRESHUFFLE,
            )
        )

    def test_compv5_rejected_on_gfx1250_only(self):
        # compv5 reads BlockGemm::Traits::KPack, which its block GEMM lacks: no build.
        for epi in ("cshuffle", "default"):
            self.assertFalse(self._valid(pipeline="compv5", epilogue=epi), epi)
            self.assertEqual(
                gfx1250_pipeline_reject_reason(
                    "gfx1250", "compv5", epi, "intrawave", 4, 32, "bf16", "bf16", "rcr"
                ),
                GFX1250_COMPV5_REJECT_REASON,
            )
        self.assertEqual(
            gfx1250_pipeline_reject_reason(
                "gfx950",
                "compv5",
                "cshuffle",
                "intrawave",
                4,
                16,
                "bf16",
                "bf16",
                "rcr",
            ),
            "",
        )

    def test_comp_async_layout(self):
        self.assertTrue(
            self._valid(pipeline="comp_async", layout="rcr", **self.PADS_TTT)
        )
        for layout in ("rrr", "crr", "ccr"):
            self.assertFalse(
                self._valid(pipeline="comp_async", layout=layout, **self.PADS_TTT),
                layout,
            )
            # Other pipelines keep every layout.
            self.assertTrue(
                self._valid(pipeline="compv3", layout=layout, **self.PADS_TTT), layout
            )

    def test_tdm_fp32_rcr_only(self):
        fp32 = dict(datatype_a="fp32", datatype_b="fp32", datatype_c="fp32")
        fp32.update(warp_tile_k=4, epilogue="tdm", **self.PADS_FFF)
        for pipe in TDM_PIPELINES:
            self.assertTrue(self._valid(pipeline=pipe, layout="rcr", **fp32), pipe)
            for layout in ("rrr", "crr", "ccr"):
                self.assertFalse(
                    self._valid(pipeline=pipe, layout=layout, **fp32), (pipe, layout)
                )
                # fp16 TDM keeps every layout.
                self.assertTrue(
                    self._valid(
                        pipeline=pipe, layout=layout, epilogue="tdm", **self.PADS_FFF
                    ),
                    (pipe, layout),
                )

    def test_comp_async_epilogue_and_scheduler(self):
        self.assertFalse(
            self._valid(pipeline="comp_async", epilogue="default", **self.PADS_TTT)
        )
        self.assertFalse(
            self._valid(pipeline="comp_async", scheduler="interwave", **self.PADS_TTT)
        )
        self.assertTrue(
            self._valid(pipeline="comp_async", epilogue="cshuffle", **self.PADS_TTT)
        )

    def test_comp_async_pads_must_be_ttt(self):
        for pads in ((False, False, False), (True, False, True), (True, True, False)):
            kw = dict(zip(("pad_m", "pad_n", "pad_k"), pads))
            self.assertFalse(self._valid(pipeline="comp_async", **kw), pads)

    def test_comp_async_fp8_warp_tile_k(self):
        for dt in ("fp8", "bf8"):
            kw = dict(datatype_a=dt, datatype_b=dt, datatype_c="fp16", tile_k=128)
            for wtk in (32, 64):
                self.assertFalse(
                    self._valid(
                        pipeline="comp_async", warp_tile_k=wtk, **kw, **self.PADS_TTT
                    ),
                    (dt, wtk),
                )

    def test_gfx950_comp_async_still_accepted(self):
        # MX / grouped_conv comp_async on gfx950 is outside the gfx1250 gate.
        for layout in ("rcr", "rrr"):
            self.assertTrue(
                self._valid(
                    "gfx950",
                    pipeline="comp_async",
                    epilogue="cshuffle",
                    layout=layout,
                    warp_tile_m=32,
                    warp_tile_n=32,
                    warp_tile_k=16,
                    **self.PADS_FFF,
                ),
                layout,
            )

    def test_tdm_lds_row_padding(self):
        # 1120x128x64 fp16: A+B = 159744B fits the 163840B double-buffered
        # budget, but the 16B-per-256B-row-group padding of the gfx1250 base
        # LDS descriptor (TDM and non-MX comp_async) lifts it to 169696B
        # (Tile Engine validate_lds_capacity accounting).
        tile = dict(tile_m=1120, tile_n=128, tile_k=64)
        self.assertFalse(self._valid(pipeline="comp_tdm", epilogue="tdm", **tile))
        self.assertFalse(
            self._valid(
                pipeline="comp_async", epilogue="cshuffle", **tile, **self.PADS_TTT
            )
        )
        self.assertTrue(self._valid(pipeline="compv3", **tile))

    def test_tdm_c_tile_fits_lds(self):
        # 512x512 fp16 output = 512KB > 320KB LDS; A+B alone would fit.
        tile = dict(tile_m=512, tile_n=512, tile_k=64)
        self.assertFalse(self._valid(pipeline="comp_tdm", epilogue="tdm", **tile))
        self.assertTrue(self._valid(pipeline="compv3", **tile))

    def test_tdm_lds_padding_64x256x256_rejected_by_both_gates(self):
        # fp16 64x256x256: A = 32768B + 1008B pad, B = 131072B + 4080B pad,
        # 168928B > 163840B double-buffered budget. Unpadded A+B (163840B)
        # would just fit, so only the row padding rejects it -- ArchFilter
        # and the Tile Engine must agree. Non-MX comp_async uses the same
        # descriptor; without this reject it fails to link on gfx1250
        # (local memory 337856B > 327680B).
        tile = dict(tile_m=64, tile_n=256, tile_k=256)
        self.assertFalse(self._valid(pipeline="comp_tdm", epilogue="tdm", **tile))
        self.assertFalse(
            self._valid(
                pipeline="comp_async", epilogue="cshuffle", **tile, **self.PADS_TTT
            )
        )
        if te is None:
            self.skipTest("tile_engine gemm_validation_utils not importable")
        te_args = dict(
            warp_m=2,
            warp_n=2,
            warp_k=1,
            warp_tile_m=16,
            warp_tile_n=16,
            warp_tile_k=32,
            a_datatype="fp16",
            b_datatype="fp16",
            c_datatype="fp16",
            layout="rcr",
            gpu_target="gfx1250",
            kernel_name_prefix="gemm_universal",
        )
        self.assertFalse(
            te.is_tile_config_valid(
                tile_m=64, tile_n=256, tile_k=256, pipeline="comp_tdm", **te_args
            )
        )
        self.assertFalse(
            te.is_tile_config_valid(
                tile_m=64, tile_n=256, tile_k=256, pipeline="comp_async", **te_args
            )
        )
        # Controls: mx GEMM keeps its own comp_async LDS policy, and other
        # arches keep the unpadded budget.
        lds_args = dict(
            tile_m=64,
            tile_n=256,
            tile_k=256,
            a_datatype="fp16",
            b_datatype="fp16",
            pipeline="comp_async",
            gpu_target="gfx1250",
        )
        self.assertTrue(te.validate_lds_capacity(**lds_args)[0])
        self.assertFalse(
            te.validate_lds_capacity(**lds_args, gfx1250_gemm_pipeline=True)[0]
        )
        gfx950_args = {**lds_args, "gpu_target": "gfx950"}
        self.assertEqual(
            te.validate_lds_capacity(**gfx950_args),
            te.validate_lds_capacity(**gfx950_args, gfx1250_gemm_pipeline=True),
        )

    def test_comp_async_not_gated_for_grouped_conv(self):
        # The gfx1250 comp_async GEMM rules (layout/epilogue/pads) must not
        # leak into other operators such as grouped convolution.
        for arch in ("gfx950", "gfx1250"):
            for op in (OperatorType.CONV_FWD, OperatorType.CONV_BWD_WEIGHT):
                cfg = KernelConfig(
                    datatype_a="fp16",
                    datatype_b="fp16",
                    datatype_c="fp16",
                    **TDM_TILE,
                    pipeline="comp_async",
                    epilogue="default",
                    scheduler="intrawave",
                    layout="rrr",
                    operator=op,
                    pad_m=False,
                    pad_n=False,
                    pad_k=False,
                )
                res = ValidationResult(valid=True)
                ArchFilter(arch)._validate_gfx1250_pipeline(cfg, res)
                self.assertEqual(res.errors, [], (arch, op))
        # Same config as a GEMM on gfx1250 is rejected by the gate.
        cfg.operator = OperatorType.GEMM
        res = ValidationResult(valid=True)
        ArchFilter("gfx1250")._validate_gfx1250_pipeline(cfg, res)
        self.assertNotEqual(res.errors, [])


class TestTypeMappings(unittest.TestCase):
    def test_pipeline_maps(self):
        m = CommonTypeMappings
        self.assertEqual(m.PIPELINE_TO_CK["comp_tdm"], "GemmPipelineAgBgCrCompTDMV1")
        self.assertEqual(m.PIPELINE_TO_CK["comp_tdm_v2"], "GemmPipelineAgBgCrCompTDMV2")
        self.assertEqual(
            m.PIPELINE_TO_BASE["comp_tdm"], "BaseGemmPipelineAgBgCrCompTDM"
        )
        self.assertEqual(
            m.PIPELINE_TO_BASE["comp_tdm_v2"], "BaseGemmPipelineAgBgCrCompTDM"
        )
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["comp_async"], "Pipeline::CompAsync")
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["comp_tdm"], "Pipeline::CompTDMV1")
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["comp_tdm_v2"], "Pipeline::CompTDMV2")
        self.assertEqual(
            m.PIPELINE_TO_CK["comp_tdm_pc"],
            "GemmPipelineAgBgCrCompTDMProducerConsumer",
        )
        self.assertEqual(
            m.PIPELINE_TO_BASE["comp_tdm_pc"], "BaseGemmPipelineAgBgCrCompTDM"
        )
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["comp_tdm_pc"], "Pipeline::CompTDMPC")
        self.assertEqual(
            m.PIPELINE_TO_CK["comp_tdm_ra"], "GemmPipelineAgBgCrCompTDMRunAhead"
        )
        self.assertEqual(
            m.PIPELINE_TO_BASE["comp_tdm_ra"], "BaseGemmPipelineAgBgCrCompTDM"
        )
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["comp_tdm_ra"], "Pipeline::CompTDMRA")
        self.assertEqual(
            m.PIPELINE_TO_RING_POLICY,
            {
                "comp_tdm_pc": "GemmPipelineAgBgCrCompTDMProducerConsumerPolicy",
                "comp_tdm_ra": "GemmPipelineAgBgCrCompTDMRunAheadPolicy",
            },
        )
        self.assertEqual(m.EPILOGUE_TO_DISPATCHER["tdm"], "Epilogue::Tdm")

    def test_legacy_maps_unchanged(self):
        m = CommonTypeMappings
        self.assertEqual(m.PIPELINE_TO_CK["compv3"], "GemmPipelineAgBgCrCompV3")
        self.assertEqual(m.PIPELINE_TO_DISPATCHER["mem"], "Pipeline::Mem")
        self.assertEqual(m.EPILOGUE_TO_DISPATCHER["cshuffle"], "Epilogue::CShuffle")


class TestLdsBudget(unittest.TestCase):
    def test_tdm_shares_comp_async_budget(self):
        for arch in ("gfx942", "gfx950", "gfx1250"):
            for pipe in ("comp_tdm", "comp_tdm_v2"):
                self.assertEqual(
                    get_lds_limit(arch, pipe), get_lds_limit(arch, "comp_async")
                )

    def test_gfx1250_budget(self):
        self.assertEqual(get_lds_limit("gfx1250", "comp_tdm"), 163840)

    def test_comp_tdm_pc_four_slot_budget(self):
        # A quarter of the hardware LDS (NumSlots_ = 4), same as the Tile Engine
        # PIPELINE_SMEM_SLOTS entry.
        for arch, budget in (("gfx1250", 81920), ("gfx950", 40960), ("gfx942", 16384)):
            self.assertEqual(get_lds_limit(arch, "comp_tdm_pc"), budget, arch)
        if te is not None:
            self.assertEqual(te.PIPELINE_SMEM_SLOTS["comp_tdm_pc"], 4)
            self.assertEqual(te.LDS_SIZE_MAP["gfx1250"] // 4, 81920)

    def test_comp_tdm_ra_four_slot_budget(self):
        # The policy default ring <4, 3> rotates four slots, like comp_tdm_pc.
        for arch, budget in (("gfx1250", 81920), ("gfx950", 40960), ("gfx942", 16384)):
            self.assertEqual(get_lds_limit(arch, "comp_tdm_ra"), budget, arch)
        if te is not None:
            self.assertEqual(te.PIPELINE_SMEM_SLOTS["comp_tdm_ra"], 4)


def _run_codegen(outdir, arch, variant, cfg_path, layout="rcr"):
    cmd = [
        sys.executable,
        str(CODEGEN_DIR / "unified_gemm_codegen.py"),
        "--output-dir",
        str(outdir),
        "--datatype",
        "fp16",
        "--layout",
        layout,
        "--gpu-target",
        arch,
        "--config",
        str(cfg_path),
        "--variants",
        variant,
        "--no-parallel",
    ]
    subprocess.run(cmd, check=True, capture_output=True, cwd=str(CODEGEN_DIR))
    return sorted(p.name for p in Path(outdir).glob("*.hpp"))


class TestUnifiedCodegenGolden(unittest.TestCase):
    CONFIG = {
        "tile_config": {
            "tile_m": [128],
            "tile_n": [128],
            "tile_k": [64],
            "warp_m": [2, 4],
            "warp_n": [2],
            "warp_k": [1],
            "warp_tile_m": [16],
            "warp_tile_n": [16],
            "warp_tile_k": [32],
        },
        "trait_config": {
            "pipeline": [
                "comp_tdm",
                "comp_tdm_v2",
                "comp_tdm_pc",
                "comp_tdm_ra",
                "comp_async",
                "compv3",
            ],
            "epilogue": ["tdm", "cshuffle"],
            "scheduler": ["intrawave"],
            # TDM only accepts pads False and comp_async only pads True, so
            # every pad combo proves each gate drops the others.
            "pad_m": [False, True],
            "pad_n": [False, True],
            "pad_k": [False, True],
            "persistent": [False, True],
        },
    }

    @classmethod
    def setUpClass(cls):
        cls.tmp = Path(tempfile.mkdtemp(prefix="tdm_codegen_"))
        cls.cfg = cls.tmp / "cfg.json"
        cls.cfg.write_text(json.dumps(cls.CONFIG))

    @classmethod
    def tearDownClass(cls):
        shutil.rmtree(cls.tmp, ignore_errors=True)

    def _gen(self, arch, variant, layout="rcr"):
        out = self.tmp / f"{arch}_{variant}_{layout}"
        return out, _run_codegen(out, arch, variant, self.cfg, layout)

    def test_gfx1250_standard_kernel_set(self):
        out, names = self._gen("gfx1250", "standard")
        tdm = [n for n in names if "_comp_tdm_tdm_" in n]
        tdm_v2 = [n for n in names if "_comp_tdm_v2_tdm_" in n]
        tdm_pc = [n for n in names if "_comp_tdm_pc_tdm_" in n]
        tdm_ra = [n for n in names if "_comp_tdm_ra_tdm_" in n]
        async_ = [n for n in names if "_comp_async_" in n]
        # comp_tdm: 2 wave layouts, non-persistent, unpadded only.
        self.assertEqual(len(tdm), 2)
        # comp_tdm_v2: 4 waves only.
        self.assertEqual(len(tdm_v2), 1)
        self.assertIn("2x2x1", tdm_v2[0])
        # comp_tdm_pc: both wave layouts (128x128 stays under the accumulator cap).
        self.assertEqual(len(tdm_pc), 2)
        # comp_tdm_ra: both wave layouts, tdm epilogue only.
        self.assertEqual(len(tdm_ra), 2)
        self.assertFalse(any("_comp_tdm_ra_cshuffle_" in n for n in names))
        # Plain GEMM also pairs comp_tdm_pc with cshuffle (unpadded, non-persistent);
        # comp_tdm and comp_tdm_v2 never.
        tdm_pc_cshuffle = [n for n in names if "_comp_tdm_pc_cshuffle_" in n]
        self.assertEqual(len(tdm_pc_cshuffle), 2)
        for n in tdm_pc_cshuffle:
            self.assertIn("_cshuffle_intrawave_False_False_False_False_", n)
        self.assertFalse(
            any(
                "_comp_tdm_cshuffle_" in n or "_comp_tdm_v2_cshuffle_" in n
                for n in names
            )
        )
        # comp_async: 2 wave layouts x persistent on/off, fully padded,
        # cshuffle only.
        self.assertEqual(len(async_), 4)
        for n in async_:
            self.assertIn("_comp_async_cshuffle_intrawave_True_True_True_", n)
        for n in tdm + tdm_v2 + tdm_pc + tdm_ra:
            self.assertIn("_tdm_intrawave_False_False_False_False_", n)
        self.assertFalse(
            any("_compv3_tdm_" in n or "_comp_async_tdm_" in n for n in names)
        )

    def test_gfx1250_tdm_header_contents(self):
        out, names = self._gen("gfx1250", "standard")
        name = next(n for n in names if "_comp_tdm_tdm_" in n and "2x2x1" in n)
        text = (out / name).read_text()
        self.assertIn('#include "ck_tile/ops/epilogue/tdm_epilogue.hpp"', text)
        self.assertIn("GemmPipelineAgBgCrCompTDMV1<", text)
        self.assertIn("BaseGemmPipelineAgBgCrCompTDM<", text)
        self.assertIn("TdmEpilogue<", text)
        self.assertNotIn("CShuffleEpilogue<", text)
        self.assertIn("static constexpr bool DoubleSmemBuffer = true;", text)
        self.assertIn("args.k_batch != 1", text)
        wrapper = (
            out / "dispatcher_wrappers" / f"dispatcher_wrapper_{name}"
        ).read_text()
        self.assertIn("Pipeline::CompTDMV1", wrapper)
        self.assertIn("Epilogue::Tdm", wrapper)
        self.assertIn("key.algorithm.double_buffer = true;", wrapper)

    def test_gfx1250_tdm_pc_header_contents(self):
        out, names = self._gen("gfx1250", "standard")
        name = next(n for n in names if "_comp_tdm_pc_tdm_" in n and "2x2x1" in n)
        text = (out / name).read_text()
        self.assertIn("GemmPipelineAgBgCrCompTDMProducerConsumer<", text)
        self.assertIn("BaseGemmPipelineAgBgCrCompTDM<", text)
        self.assertIn("TdmEpilogue<", text)
        self.assertIn("static constexpr bool TransposeC = false;", text)
        self.assertIn("static constexpr bool DoubleSmemBuffer = true;", text)
        wrapper = (
            out / "dispatcher_wrappers" / f"dispatcher_wrapper_{name}"
        ).read_text()
        self.assertIn("Pipeline::CompTDMPC", wrapper)
        self.assertIn("Epilogue::Tdm", wrapper)

    def test_gfx1250_tdm_pc_cshuffle_header_contents(self):
        out, names = self._gen("gfx1250", "standard")
        name = next(n for n in names if "_comp_tdm_pc_cshuffle_" in n and "2x2x1" in n)
        text = (out / name).read_text()
        self.assertIn("GemmPipelineAgBgCrCompTDMProducerConsumer<", text)
        self.assertIn("CShuffleEpilogue<", text)
        self.assertNotIn("TdmEpilogue<", text)
        # Split-K is why this pairing exists: GemmKernel::IsSupportedArgument validates
        # k_batch, as in the Tile Engine instance builder (_tdm_k_batch_guard).
        self.assertNotIn("args.k_batch != 1", text)
        wrapper = (
            out / "dispatcher_wrappers" / f"dispatcher_wrapper_{name}"
        ).read_text()
        self.assertIn("Pipeline::CompTDMPC", wrapper)
        self.assertIn("Epilogue::CShuffle", wrapper)

    def test_gfx1250_tdm_ra_header_contents(self):
        out, names = self._gen("gfx1250", "standard")
        name = next(n for n in names if "_comp_tdm_ra_tdm_" in n and "2x2x1" in n)
        # The default ring <4, 3> keeps the suffix-free name.
        self.assertTrue(name.endswith("_16x16x32.hpp"), name)
        text = (out / name).read_text()
        self.assertIn('#include "ck_tile/ops/epilogue/tdm_epilogue.hpp"', text)
        self.assertIn("GemmPipelineAgBgCrCompTDMRunAhead<UniversalGemmProblem>;", text)
        self.assertNotIn("GemmPipelineAgBgCrCompTDMRunAheadPolicy", text)
        self.assertIn("BaseGemmPipelineAgBgCrCompTDM<", text)
        self.assertIn("TdmEpilogue<", text)
        self.assertNotIn("CShuffleEpilogue<", text)
        self.assertIn("static constexpr bool DoubleSmemBuffer = true;", text)
        # Not split-K capable: TdmEpilogue overwrites C.
        self.assertIn("args.k_batch != 1", text)
        self.assertIn('#define GEMM_KEY_PIPELINE "comp_tdm_ra"', text)
        self.assertIn("#define GEMM_KEY_NUM_SLOTS 0", text)
        self.assertIn("#define GEMM_KEY_RUN_AHEAD 0", text)
        wrapper = (
            out / "dispatcher_wrappers" / f"dispatcher_wrapper_{name}"
        ).read_text()
        self.assertIn("Pipeline::CompTDMRA", wrapper)
        self.assertIn("Epilogue::Tdm", wrapper)
        self.assertIn("key.algorithm.num_slots = 0;", wrapper)
        self.assertIn("key.algorithm.run_ahead = 0;", wrapper)

    def test_gfx1250_compv3_header_has_no_tdm(self):
        out, names = self._gen("gfx1250", "standard")
        name = next(n for n in names if "_compv3_" in n)
        text = (out / name).read_text()
        self.assertNotIn("tdm_epilogue.hpp", text)
        self.assertNotIn("TDM", text)
        self.assertIn("static constexpr bool DoubleSmemBuffer = false;", text)

    def test_gfx942_only_compv3(self):
        for variant in ("standard", "batched"):
            _, names = self._gen("gfx942", variant)
            self.assertTrue(names)
            self.assertTrue(all("_compv3_cshuffle_" in n for n in names), names)

    def test_gfx1250_batched_has_tdm(self):
        _, names = self._gen("gfx1250", "batched")
        self.assertTrue(any("_comp_tdm_tdm_" in n for n in names))
        self.assertTrue(any("_comp_tdm_v2_tdm_" in n for n in names))
        # BatchedGemmKernel arms the producer/consumer barriers.
        self.assertTrue(any("_comp_tdm_pc_tdm_" in n for n in names))
        # comp_tdm_ra is plain GEMM only.
        self.assertFalse(any("_comp_tdm_ra_" in n for n in names))

    def test_gfx1250_batched_comp_async_epilogue_double_smem(self):
        out, names = self._gen("gfx1250", "batched")
        name = next(n for n in names if "_comp_async_cshuffle_" in n)
        text = (out / name).read_text()
        self.assertIn(
            "UniversalGemmProblem::TransposeC, 1, false, 1, 1, DoubleSmemBuffer", text
        )
        name = next(n for n in names if "_compv3_cshuffle_" in n)
        self.assertNotIn(", DoubleSmemBuffer>", (out / name).read_text())

    def test_comp_async_requires_cshuffle_intrawave(self):
        cfg = json.loads(json.dumps(self.CONFIG))
        cfg["trait_config"]["pipeline"] = ["comp_async"]
        cfg["trait_config"]["epilogue"] = ["cshuffle", "default", "tdm"]
        cfg["trait_config"]["scheduler"] = ["intrawave", "interwave"]
        path = self.tmp / "async_cfg.json"
        path.write_text(json.dumps(cfg))
        names = _run_codegen(self.tmp / "async_only", "gfx1250", "standard", path)
        self.assertTrue(names)
        for n in names:
            self.assertIn("_comp_async_cshuffle_intrawave_", n)

    def test_tdm_rejects_any_pad(self):
        for pad in ("pad_m", "pad_n", "pad_k"):
            cfg = json.loads(json.dumps(self.CONFIG))
            cfg["trait_config"]["pad_m"] = [False]
            cfg["trait_config"]["pad_n"] = [False]
            cfg["trait_config"]["pad_k"] = [False]
            cfg["trait_config"][pad] = [True]
            path = self.tmp / f"tdm_{pad}.json"
            path.write_text(json.dumps(cfg))
            for variant in ("standard", "batched"):
                names = _run_codegen(
                    self.tmp / f"tdm_{pad}_{variant}", "gfx1250", variant, path
                )
                self.assertFalse(any("_comp_tdm" in n for n in names), (pad, names))
                # A single pad is not enough for comp_async either.
                self.assertFalse(any("_comp_async_" in n for n in names), pad)
                self.assertTrue(any("_compv3_" in n for n in names), pad)

    def test_comp_async_rc_layout_only(self):
        for layout in ("rrr", "crr", "ccr"):
            _, names = self._gen("gfx1250", "standard", layout)
            self.assertFalse(any("_comp_async_" in n for n in names), layout)
            # TDM is not layout-gated.
            self.assertTrue(any("_comp_tdm_tdm_" in n for n in names), layout)
            self.assertTrue(any("_comp_tdm_v2_tdm_" in n for n in names), layout)
            self.assertTrue(any("_comp_tdm_pc_tdm_" in n for n in names), layout)
            self.assertTrue(any("_comp_tdm_ra_tdm_" in n for n in names), layout)

    def test_gfx1250_reject_reason_strings(self):
        import unified_gemm_codegen as ugc

        self.assertIn("pad_m=pad_n=pad_k=False", ugc.TDM_PAD_REJECT_REASON)
        self.assertIn(
            "A row-major and B col-major", ugc.GFX1250_COMP_ASYNC_LAYOUT_REJECT_REASON
        )
        self.assertIn("pad_m=pad_n=pad_k=True", GFX1250_COMP_ASYNC_PAD_REJECT_REASON)
        self.assertIs(
            ugc.GFX1250_COMP_ASYNC_PAD_REJECT_REASON,
            GFX1250_COMP_ASYNC_PAD_REJECT_REASON,
        )
        # Same text as the Tile Engine gate.
        te_gemm = DISPATCHER_DIR.parent / "tile_engine" / "ops" / "gemm"
        te_src = (te_gemm / "gemm_validation_utils.py").read_text()
        te_text = "".join(GFX1250_COMP_ASYNC_PAD_REJECT_REASON.split())
        self.assertIn(te_text, "".join(te_src.replace('"', "").split()))

    def test_multi_d_no_gfx1250_pipelines(self):
        _, names = self._gen("gfx1250", "multi_d")
        self.assertTrue(names)
        self.assertFalse(any("comp_async" in n or "comp_tdm" in n for n in names))

    def test_grouped_no_gfx1250_pipelines(self):
        _, names = self._gen("gfx1250", "grouped")
        self.assertTrue(names)
        self.assertFalse(any("comp_async" in n or "comp_tdm" in n for n in names))

    def test_stream_k_gfx1250_pipelines(self):
        # Without a streamk_config only atomic reduction is built, which needs the
        # cshuffle epilogue. Of the gfx1250-only pipelines, only those in
        # STREAMK_GFX1250_PIPELINES (comp_tdm, comp_tdm_v2 and comp_tdm_pc) are built;
        # test_streamk_tdm_gfx1250.py covers the comp_tdm/comp_tdm_v2 rules and
        # TestStreamKCodegen the comp_tdm_pc ones.
        _, names = self._gen("gfx1250", "stream_k")
        self.assertTrue(names)
        self.assertFalse(any("comp_async" in n for n in names))
        for pipe in ("comp_tdm", "comp_tdm_v2", "comp_tdm_pc", "comp_tdm_ra"):
            built = any(f"_{pipe}_cshuffle_" in n for n in names)
            self.assertEqual(built, pipe in STREAMK_GFX1250_PIPELINES, pipe)
        self.assertFalse(any("_comp_tdm_ra_" in n for n in names))
        tdm = [n for n in names if "_comp_tdm" in n]
        for n in tdm:
            self.assertIn("_cshuffle_intrawave_False_False_False_", n)
            self.assertTrue(n.endswith("_streamk.hpp"), n)
        # Stream-K's persistent kernel hosts the comp_tdm_pc ring too.
        tdm_pc = [n for n in tdm if "_comp_tdm_pc_" in n]
        self.assertTrue(any("_False_False_False_True_" in n for n in tdm_pc))


class TestCompTdmPcRing(unittest.TestCase):
    """comp_tdm_pc NumSlots/PublishLag: "comp_tdm_pc_s{S}l{L}" pipeline variants."""

    RING_CONFIG = {
        "tile_config": dict(TestUnifiedCodegenGolden.CONFIG["tile_config"], warp_m=[2]),
        "trait_config": dict(
            TestUnifiedCodegenGolden.CONFIG["trait_config"],
            pipeline=["comp_tdm_pc", "comp_tdm_pc_s2l1", "comp_tdm_pc_s4l0"],
            epilogue=["tdm"],
            pad_m=[False],
            pad_n=[False],
            pad_k=[False],
            persistent=[False],
        ),
    }

    def test_split_pipeline_ring(self):
        self.assertEqual(split_pipeline_ring("comp_tdm_pc"), ("comp_tdm_pc", 0, 0))
        self.assertEqual(split_pipeline_ring("comp_tdm_pc_s2l1"), ("comp_tdm_pc", 2, 1))
        # The policy default keeps the default (suffix-free) name.
        self.assertEqual(split_pipeline_ring("comp_tdm_pc_s4l0"), ("comp_tdm_pc", 0, 0))
        self.assertEqual(split_pipeline_ring("comp_tdm_s2l1"), ("comp_tdm_s2l1", 0, 0))
        self.assertEqual(split_pipeline_ring("compv3"), ("compv3", 0, 0))
        self.assertEqual(pipeline_ring_suffix("comp_tdm_pc", 0, 0), "")
        self.assertEqual(pipeline_ring_suffix("comp_tdm_pc", 3, 2), "_s3l2")

    @unittest.skipIf(te is None, "tile_engine not present")
    def test_matches_tile_engine(self):
        for name in (
            "comp_tdm_pc",
            "comp_tdm_pc_s2l1",
            "comp_tdm_pc_s4l0",
            "comp_tdm_pc_s5l4",
            "comp_tdm_pc_s1l0",
            "comp_tdm_pc_s6l0",
            "comp_tdm_pc_s3l3",
            "comp_tdm_v2",
        ):
            ring = split_pipeline_ring(name)
            self.assertEqual(te.split_pipeline_ring(name), ring, name)
            self.assertEqual(
                bool(te.pipeline_ring_reject_reason(name)),
                bool(comp_tdm_pc_ring_reject_reason(*ring)),
                name,
            )

    def test_ring_reject_reason(self):
        for slots, lag in ((0, 0), (2, 0), (2, 1), (4, 3), (5, 4)):
            self.assertEqual(
                comp_tdm_pc_ring_reject_reason("comp_tdm_pc", slots, lag), ""
            )
        for slots, lag in ((1, 0), (6, 0), (3, 3), (2, -1), (0, 1)):
            self.assertTrue(
                comp_tdm_pc_ring_reject_reason("comp_tdm_pc", slots, lag), (slots, lag)
            )
        self.assertIn("only apply to", comp_tdm_pc_ring_reject_reason("comp_tdm", 2, 1))

    def test_gate_checks_ring(self):
        args = dict(
            num_waves=4, warp_tile_k=32, dtype_a="fp16", dtype_b="fp16", layout="rcr"
        )
        ok = gfx1250_pipeline_reject_reason(
            "gfx1250", "comp_tdm_pc", "tdm", "intrawave", ring=(3, 1), **args
        )
        self.assertEqual(ok, "")
        bad = gfx1250_pipeline_reject_reason(
            "gfx1250", "comp_tdm_pc", "tdm", "intrawave", ring=(6, 0), **args
        )
        self.assertIn("num_slots=6", bad)
        # A ring on a pipeline outside the gfx1250 gate is still rejected.
        self.assertIn(
            "only apply to",
            gfx1250_pipeline_reject_reason(
                "gfx942", "compv3", "cshuffle", "intrawave", ring=(2, 0), **args
            ),
        )

    def test_lds_budget_follows_slots(self):
        # fp16 rcr 256x128x128 on 4x2x1 waves needs 104416B per slot: over the
        # default ring's 81920B, under 327680 / 3 and 327680 / 2.
        tile = dict(TDM_TILE, tile_m=256, tile_n=128, tile_k=128, warp_m=4)
        filt = ArchFilter("gfx1250")
        kw = dict(tile, pipeline="comp_tdm_pc", epilogue="tdm")
        self.assertFalse(filt.is_kernel_valid(**kw))
        self.assertFalse(filt.is_kernel_valid(**kw, num_slots=4))
        self.assertTrue(filt.is_kernel_valid(**kw, num_slots=3))
        self.assertTrue(filt.is_kernel_valid(**kw, num_slots=2))

    def test_codegen_emits_ring_policy(self):
        with tempfile.TemporaryDirectory() as td:
            cfg = Path(td) / "cfg.json"
            cfg.write_text(json.dumps(self.RING_CONFIG))
            out = Path(td) / "out"
            names = _run_codegen(out, "gfx1250", "standard", cfg)
            # s4l0 is the default ring and folds into the plain comp_tdm_pc kernel.
            self.assertEqual(len(names), 2, names)
            ring = [n for n in names if n.endswith("_s2l1.hpp")]
            self.assertEqual(len(ring), 1, names)
            text = (out / ring[0]).read_text()
            self.assertIn(
                "GemmPipelineAgBgCrCompTDMProducerConsumer<UniversalGemmProblem, "
                "GemmPipelineAgBgCrCompTDMProducerConsumerPolicy<2, 1>>",
                text,
            )
            self.assertIn("#define GEMM_KEY_NUM_SLOTS 2", text)
            self.assertIn("#define GEMM_KEY_PUBLISH_LAG 1", text)
            wrapper = (
                out / "dispatcher_wrappers" / f"dispatcher_wrapper_{ring[0]}"
            ).read_text()
            self.assertIn("key.algorithm.num_slots = 2;", wrapper)
            self.assertIn("key.algorithm.publish_lag = 1;", wrapper)
            default = next(n for n in names if n not in ring)
            self.assertNotIn(
                "GemmPipelineAgBgCrCompTDMProducerConsumerPolicy",
                (out / default).read_text(),
            )

    def test_expand_sweep_names_match_codegen(self):
        import gemm_utils

        cfg = {
            section: {k: {"values": v} for k, v in entries.items()}
            for section, entries in self.RING_CONFIG.items()
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
            self.assertEqual(
                sorted((c.num_slots, c.publish_lag) for c in got), [(0, 0), (2, 1)]
            )
            ring = next(c for c in got if c.num_slots)
            self.assertEqual(ring.pipeline, "comp_tdm_pc")
            self.assertEqual(
                ring.to_codegen_json()["trait_config"]["pipeline"], ["comp_tdm_pc_s2l1"]
            )
            cg = Path(td) / "cg.json"
            cg.write_text(json.dumps(self.RING_CONFIG))
            names = _run_codegen(Path(td) / "out", "gfx1250", "standard", cg)
        self.assertEqual(sorted(f"{c.name}.hpp" for c in got), names)

    def test_expand_sweep_lds_follows_slots(self):
        import gemm_utils

        tile = dict(
            tile_m=[256],
            tile_n=[128],
            tile_k=[128],
            warp_m=[4],
            warp_n=[2],
            warp_k=[1],
            warp_tile_m=[16],
            warp_tile_n=[16],
            warp_tile_k=[32],
        )
        trait = dict(
            pipeline=["comp_tdm_pc", "comp_tdm_pc_s3l1", "comp_tdm_pc_s6l0"],
            epilogue=["tdm"],
            scheduler=["intrawave"],
            pad_m=[False],
            pad_n=[False],
            pad_k=[False],
            persistent=[False],
        )
        cfg = {
            "tile_config": {k: {"values": v} for k, v in tile.items()},
            "trait_config": {k: {"values": v} for k, v in trait.items()},
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
        # The default ring overflows LDS and six slots exceed the named barriers.
        self.assertEqual([(c.num_slots, c.publish_lag) for c in got], [(3, 1)])


class TestCompTdmRaRing(unittest.TestCase):
    """comp_tdm_ra NumSlots/RunAhead: "comp_tdm_ra_s{S}r{R}" pipeline variants and
    the comp_tdm_ra gate rules."""

    RING_CONFIG = {
        "tile_config": dict(TestUnifiedCodegenGolden.CONFIG["tile_config"], warp_m=[2]),
        "trait_config": dict(
            TestUnifiedCodegenGolden.CONFIG["trait_config"],
            pipeline=["comp_tdm_ra", "comp_tdm_ra_s3r2", "comp_tdm_ra_s4r3"],
            epilogue=["tdm"],
            pad_m=[False],
            pad_n=[False],
            pad_k=[False],
            persistent=[False],
        ),
    }
    # Ring names both copies (here and the Tile Engine) must split and judge alike.
    RING_NAMES = (
        "comp_tdm_ra",
        "comp_tdm_ra_s3r2",
        "comp_tdm_ra_s4r3",
        "comp_tdm_ra_s2r1",
        "comp_tdm_ra_s8r7",
        "comp_tdm_ra_s2r2",
        "comp_tdm_ra_s1r0",
        "comp_tdm_ra_s3r0",
        "comp_tdm_ra_s0r1",
        "comp_tdm_ra_s0r2",
        "comp_tdm_pc_s0l1",
        "comp_tdm_ra_s2l1",
        "comp_tdm_pc_s2l1",
        "comp_tdm_pc_s2r1",
        "comp_tdm_pc_s4l0",
        "comp_tdm_v2",
    )
    GATE_ARGS = dict(
        num_waves=4, warp_tile_k=32, dtype_a="fp16", dtype_b="fp16", layout="rcr"
    )

    def _reason(self, epilogue="tdm", arch="gfx1250", scheduler="intrawave", **kw):
        return gfx1250_pipeline_reject_reason(
            arch, "comp_tdm_ra", epilogue, scheduler, **{**self.GATE_ARGS, **kw}
        )

    def test_split_pipeline_ring(self):
        cases = {
            "comp_tdm_ra": ("comp_tdm_ra", 0, 0),
            "comp_tdm_ra_s3r2": ("comp_tdm_ra", 3, 2),
            # The policy default keeps the default (suffix-free) name.
            "comp_tdm_ra_s4r3": ("comp_tdm_ra", 0, 0),
            # The ring letter must match the pipeline.
            "comp_tdm_ra_s2l1": ("comp_tdm_ra_s2l1", 0, 0),
            "comp_tdm_pc_s2r1": ("comp_tdm_pc_s2r1", 0, 0),
            "comp_tdm_pc_s2l1": ("comp_tdm_pc", 2, 1),
            # Out-of-range rings still split; the reject helper refuses them.
            "comp_tdm_ra_s2r2": ("comp_tdm_ra", 2, 2),
            "comp_tdm_ra_s1r0": ("comp_tdm_ra", 1, 0),
        }
        for name, want in cases.items():
            self.assertEqual(split_pipeline_ring(name), want, name)
        self.assertEqual(pipeline_ring_suffix("comp_tdm_ra", 3, 2), "_s3r2")
        self.assertEqual(pipeline_ring_suffix("comp_tdm_ra", 0, 0), "")

    def test_ring_fields(self):
        self.assertEqual(
            pipeline_ring_fields("comp_tdm_ra", 3, 2),
            dict(num_slots=3, publish_lag=0, run_ahead=2),
        )
        self.assertEqual(
            pipeline_ring_fields("comp_tdm_pc", 2, 1),
            dict(num_slots=2, publish_lag=1, run_ahead=0),
        )
        for name in ("comp_tdm_ra_s3r2", "comp_tdm_pc_s2l1"):
            base, slots, param = split_pipeline_ring(name)
            fields = pipeline_ring_fields(base, slots, param)
            self.assertEqual(
                pipeline_ring_param(base, fields["publish_lag"], fields["run_ahead"]),
                param,
            )
            self.assertEqual(base + pipeline_ring_suffix(base, slots, param), name)
        self.assertEqual(pipeline_ring_lds_limit("comp_tdm_ra", 327680, 0), 81920)
        self.assertEqual(pipeline_ring_lds_limit("comp_tdm_ra", 327680, 3), 109226)

    def test_stray_ring_field_raises(self):
        # The other ring pipeline's field reaches only the kernel name, so a
        # trait/config that sets it fails fast instead of naming the wrong ring.
        import gemm_utils
        from unified_gemm_codegen import TraitConfig

        traits = dict(epilogue="tdm", scheduler="intrawave")
        traits.update(pad_m=False, pad_n=False, pad_k=False)
        stray = (
            ("comp_tdm_pc", dict(num_slots=3, publish_lag=1, run_ahead=2)),
            ("comp_tdm_ra", dict(num_slots=3, publish_lag=1, run_ahead=2)),
            ("comp_tdm_pc", dict(num_slots=0, publish_lag=0, run_ahead=2)),
            ("comp_tdm_ra", dict(num_slots=0, publish_lag=1, run_ahead=0)),
        )
        for pipeline, ring in stray:
            with self.assertRaises(ValueError, msg=(pipeline, ring)):
                pipeline_ring_param(pipeline, ring["publish_lag"], ring["run_ahead"])
            trait = TraitConfig(pipeline=pipeline, **traits, **ring)
            with self.assertRaises(ValueError, msg=(pipeline, ring)):
                trait.ring_suffix
            config = gemm_utils.GemmKernelConfig(pipeline=pipeline, **ring)
            with self.assertRaises(ValueError, msg=(pipeline, ring)):
                config.name
        # Each pipeline's own field is accepted.
        self.assertEqual(
            TraitConfig(
                pipeline="comp_tdm_ra", **traits, num_slots=3, run_ahead=2
            ).ring_suffix,
            "_s3r2",
        )
        self.assertEqual(
            gemm_utils.GemmKernelConfig(
                pipeline="comp_tdm_pc", num_slots=3, publish_lag=1
            ).ring_suffix,
            "_s3l1",
        )

    @unittest.skipIf(te is None, "tile_engine not present")
    def test_matches_tile_engine(self):
        for name in self.RING_NAMES:
            ring = split_pipeline_ring(name)
            self.assertEqual(te.split_pipeline_ring(name), ring, name)
            self.assertEqual(
                bool(te.pipeline_ring_reject_reason(name)),
                bool(pipeline_ring_reject_reason(*ring)),
                name,
            )

    def test_ring_reject_reason(self):
        for slots, ahead in ((0, 0), (2, 1), (3, 1), (3, 2), (4, 1), (8, 7), (16, 1)):
            self.assertEqual(
                pipeline_ring_reject_reason("comp_tdm_ra", slots, ahead), ""
            )
            self.assertEqual(
                comp_tdm_ra_ring_reject_reason("comp_tdm_ra", slots, ahead), ""
            )
        for slots, ahead in ((1, 0), (2, 0), (2, 2), (3, 3), (3, -1), (0, 1)):
            self.assertTrue(
                pipeline_ring_reject_reason("comp_tdm_ra", slots, ahead),
                (slots, ahead),
            )
        # A ring only applies to comp_tdm_pc / comp_tdm_ra.
        for pipeline in ("comp_tdm", "compv3"):
            self.assertIn(
                "only apply to", pipeline_ring_reject_reason(pipeline, 3, 2), pipeline
            )
        # comp_tdm_pc keeps its own rule (and comp_tdm_pc_ring_reject_reason its
        # messages) under the generic helper.
        for slots, lag in ((2, 0), (5, 4), (1, 0), (6, 0), (3, 3), (0, 1)):
            self.assertEqual(
                pipeline_ring_reject_reason("comp_tdm_pc", slots, lag),
                comp_tdm_pc_ring_reject_reason("comp_tdm_pc", slots, lag),
            )
        self.assertIn(
            "only apply to comp_tdm_pc",
            comp_tdm_pc_ring_reject_reason("comp_tdm_ra", 3, 2),
        )

    def test_gate_rules(self):
        self.assertEqual(self._reason(), "")
        self.assertEqual(self._reason(ring=(3, 2)), "")
        self.assertIn("run_ahead=0", self._reason(ring=(3, 0)))
        self.assertIn("run_ahead=2", self._reason(ring=(2, 2)))
        for epilogue in ("cshuffle", "default"):
            self.assertIn("requires epilogue=tdm", self._reason(epilogue), epilogue)
        self.assertIn("requires gfx1250", self._reason(arch="gfx950"))
        self.assertIn("intrawave", self._reason(scheduler="interwave"))
        self.assertEqual(
            self._reason(batched=True, variant_name="batched"),
            COMP_TDM_RA_BATCHED_REJECT_REASON,
        )
        self.assertIn("stream_k", self._reason(streamk=True, variant_name="stream_k"))
        self.assertIn(
            "not supported for grouped",
            self._reason(variant_supported=False, variant_name="grouped"),
        )
        self.assertIn("persistent", self._reason(persistent=True))
        for pads in ((True, False, False), (False, True, False), (False, False, True)):
            self.assertEqual(self._reason(pads=pads), TDM_PAD_REJECT_REASON, pads)
        self.assertEqual(self._reason(warp_k=2), COMP_TDM_RA_WARP_K_REJECT_REASON)
        self.assertEqual(self._reason(warp_k=1), "")
        # No accumulator cap: 256x256 over 4 waves is 512 accumulators per lane.
        self.assertEqual(self._reason(tile_mn=(256, 256)), "")
        self.assertIn(
            "gemm_preshuffle has no comp_tdm_ra kernel",
            preshuffle_pipeline_reject_reason("comp_tdm_ra", "gfx1250"),
        )

    def test_gemm_utils_gate(self):
        import gemm_utils

        def ok(epi="tdm", waves=(2, 2, 1), variant="standard", **kw):
            return gemm_utils._gfx1250_pipeline_supported(
                "comp_tdm_ra", "intrawave", epi, False, *waves, "gfx1250", variant, **kw
            )

        self.assertTrue(ok())
        self.assertTrue(ok(tile_mn=(256, 256)))
        self.assertTrue(ok(ring=(3, 2)))
        self.assertFalse(ok(ring=(3, 3)))
        self.assertFalse(ok("cshuffle"))
        self.assertFalse(ok(waves=(1, 2, 2)))
        for variant in ("batched", "stream_k", "multi_d", "grouped", "multi_abd"):
            self.assertFalse(ok(variant=variant), variant)

    def test_lds_budget_follows_slots(self):
        # fp16 rcr 256x128x128 on 4x2x1 waves needs 104416B per slot: over the
        # default ring's 81920B, under 327680 / 3 and 327680 / 2.
        tile = dict(TDM_TILE, tile_m=256, tile_n=128, tile_k=128, warp_m=4)
        filt = ArchFilter("gfx1250")
        kw = dict(tile, pipeline="comp_tdm_ra", epilogue="tdm")
        self.assertFalse(filt.is_kernel_valid(**kw))
        self.assertFalse(filt.is_kernel_valid(**kw, num_slots=4, ring_param=3))
        self.assertTrue(filt.is_kernel_valid(**kw, num_slots=3, ring_param=2))
        self.assertTrue(filt.is_kernel_valid(**kw, num_slots=2, ring_param=1))
        # The arch filter checks the RunAhead too.
        self.assertFalse(filt.is_kernel_valid(**kw, num_slots=3))

    def test_codegen_emits_ring_policy(self):
        with tempfile.TemporaryDirectory() as td:
            cfg = Path(td) / "cfg.json"
            cfg.write_text(json.dumps(self.RING_CONFIG))
            out = Path(td) / "out"
            names = _run_codegen(out, "gfx1250", "standard", cfg)
            # s4r3 is the default ring and folds into the plain comp_tdm_ra kernel.
            self.assertEqual(len(names), 2, names)
            ring = [n for n in names if n.endswith("_s3r2.hpp")]
            self.assertEqual(len(ring), 1, names)
            text = (out / ring[0]).read_text()
            self.assertIn(
                "GemmPipelineAgBgCrCompTDMRunAhead<UniversalGemmProblem, "
                "GemmPipelineAgBgCrCompTDMRunAheadPolicy<3, 2>>",
                text,
            )
            self.assertIn("TdmEpilogue<", text)
            self.assertIn("args.k_batch != 1", text)
            self.assertIn("#define GEMM_KEY_NUM_SLOTS 3", text)
            self.assertIn("#define GEMM_KEY_PUBLISH_LAG 0", text)
            self.assertIn("#define GEMM_KEY_RUN_AHEAD 2", text)
            wrapper = (
                out / "dispatcher_wrappers" / f"dispatcher_wrapper_{ring[0]}"
            ).read_text()
            self.assertIn("Pipeline::CompTDMRA", wrapper)
            self.assertIn("key.algorithm.num_slots = 3;", wrapper)
            self.assertIn("key.algorithm.publish_lag = 0;", wrapper)
            self.assertIn("key.algorithm.run_ahead = 2;", wrapper)
            default = next(n for n in names if n not in ring)
            default_text = (out / default).read_text()
            self.assertIn(
                "GemmPipelineAgBgCrCompTDMRunAhead<UniversalGemmProblem>;", default_text
            )
            self.assertNotIn("GemmPipelineAgBgCrCompTDMRunAheadPolicy", default_text)

    def test_codegen_big_tile_and_variants(self):
        cfg = json.loads(json.dumps(self.RING_CONFIG))
        cfg["tile_config"].update(tile_m=[256], tile_n=[256], tile_k=[32])
        cfg["trait_config"]["pipeline"] = ["comp_tdm_ra", "comp_tdm_pc", "comp_tdm"]
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            names = _run_codegen(Path(td) / "standard", "gfx1250", "standard", path)
            # No accumulator cap for comp_tdm_ra; comp_tdm_pc's 256 rejects it.
            ra = [n for n in names if "_comp_tdm_ra_" in n]
            self.assertEqual(len(ra), 1, names)
            self.assertIn("_256x256x32_2x2x1_", ra[0])
            self.assertFalse(any("_comp_tdm_pc_" in n for n in names), names)
            # comp_tdm is the control: the tile itself is legal for these variants.
            for variant in ("batched", "preshuffle"):
                names = _run_codegen(Path(td) / variant, "gfx1250", variant, path)
                self.assertTrue(any("_comp_tdm_tdm_" in n for n in names), variant)
                self.assertFalse(any("comp_tdm_ra" in n for n in names), variant)

    def test_expand_sweep_names_match_codegen(self):
        import gemm_utils

        cfg = {
            section: {k: {"values": v} for k, v in entries.items()}
            for section, entries in self.RING_CONFIG.items()
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
            self.assertEqual(
                sorted((c.num_slots, c.publish_lag, c.run_ahead) for c in got),
                [(0, 0, 0), (3, 0, 2)],
            )
            ring = next(c for c in got if c.num_slots)
            self.assertEqual(ring.pipeline, "comp_tdm_ra")
            self.assertTrue(ring.name.endswith("_s3r2"), ring.name)
            self.assertEqual(ring.to_dict()["ring"], [3, 2])
            self.assertEqual(
                ring.to_codegen_json()["trait_config"]["pipeline"], ["comp_tdm_ra_s3r2"]
            )
            cg = Path(td) / "cg.json"
            cg.write_text(json.dumps(self.RING_CONFIG))
            names = _run_codegen(Path(td) / "out", "gfx1250", "standard", cg)
        self.assertEqual(sorted(f"{c.name}.hpp" for c in got), names)

    def test_expand_sweep_lds_follows_slots(self):
        import gemm_utils

        tile = dict(
            tile_m=[256],
            tile_n=[128],
            tile_k=[128],
            warp_m=[4],
            warp_n=[2],
            warp_k=[1],
            warp_tile_m=[16],
            warp_tile_n=[16],
            warp_tile_k=[32],
        )
        trait = dict(
            pipeline=["comp_tdm_ra", "comp_tdm_ra_s3r2", "comp_tdm_ra_s2r2"],
            epilogue=["tdm"],
            scheduler=["intrawave"],
            pad_m=[False],
            pad_n=[False],
            pad_k=[False],
            persistent=[False],
        )
        cfg = {
            "tile_config": {k: {"values": v} for k, v in tile.items()},
            "trait_config": {k: {"values": v} for k, v in trait.items()},
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
        # The default ring overflows LDS and RunAhead must stay below NumSlots.
        self.assertEqual([(c.num_slots, c.run_ahead) for c in got], [(3, 2)])


class TestStreamKCodegen(unittest.TestCase):
    """comp_tdm_pc Stream-K kernels: the epilogue follows the reduction strategy."""

    CONFIG = {
        "tile_config": {
            "tile_m": [128],
            "tile_n": [128],
            "tile_k": [64],
            "warp_m": [2],
            "warp_n": [2],
            "warp_k": [1],
            "warp_tile_m": [16],
            "warp_tile_n": [16],
            "warp_tile_k": [32],
        },
        "trait_config": {
            "pipeline": ["comp_tdm_pc"],
            "epilogue": ["tdm", "cshuffle"],
            "scheduler": ["intrawave"],
            "pad_m": [False, True],
            "pad_n": [False],
            "pad_k": [False],
            "persistent": [False],
        },
        "streamk_config": {"reduction_strategy": ["atomic", "linear", "tree"]},
    }

    @classmethod
    def setUpClass(cls):
        cls.tmp = Path(tempfile.mkdtemp(prefix="tdm_pc_streamk_"))
        cfg = cls.tmp / "cfg.json"
        cfg.write_text(json.dumps(cls.CONFIG))
        cls.out = cls.tmp / "out"
        cls.names = _run_codegen(cls.out, "gfx1250", "stream_k", cfg)

    @classmethod
    def tearDownClass(cls):
        shutil.rmtree(cls.tmp, ignore_errors=True)

    def test_kernel_set(self):
        # atomic: cshuffle only; linear/tree: both epilogues; padded TDM never.
        self.assertEqual(len(self.names), 5, self.names)
        self.assertEqual(sum(n.endswith("_streamk.hpp") for n in self.names), 1)
        self.assertIn(
            "_cshuffle_", next(n for n in self.names if n.endswith("_streamk.hpp"))
        )
        for strategy in ("linear", "tree"):
            epilogues = sorted(
                "tdm" if "_comp_tdm_pc_tdm_" in n else "cshuffle"
                for n in self.names
                if n.endswith(f"_streamk_{strategy}.hpp")
            )
            self.assertEqual(epilogues, ["cshuffle", "tdm"], strategy)
        self.assertFalse(any("_intrawave_True_" in n for n in self.names), self.names)

    def test_tdm_epilogue_header(self):
        name = next(
            n
            for n in self.names
            if "_comp_tdm_pc_tdm_" in n and n.endswith("_linear.hpp")
        )
        text = (self.out / name).read_text()
        self.assertIn("GemmPipelineAgBgCrCompTDMProducerConsumer", text)
        self.assertIn("TdmEpilogue<EpilogueProblem>", text)
        self.assertIn("StreamKReductionStrategy::Linear", text)

    def test_tile_engine_sweep_config(self):
        # The streamk_gemm_full_benchmark.py sweep config: atomic on cshuffle only,
        # linear and tree on both epilogues, each persistent and not, and the kernel
        # name carries the epilogue, persistence and strategy it is built with.
        import gemm_utils

        path = (
            TE_GEMM_DIR / "gemm_streamk" / "configs" / "gfx1250_comp_tdm_pc_config.json"
        )
        cfgs = gemm_utils.expand_sweep(
            str(path), "gfx1250", "fp16", "rcr", variant="stream_k"
        )
        self.assertEqual(
            {
                (c.pipeline, c.epilogue, c.reduction_strategy, c.persistent)
                for c in cfgs
            },
            {
                ("comp_tdm_pc", epi, strategy, persistent)
                for strategy in ("atomic", "linear", "tree")
                for epi in (
                    ("cshuffle",) if strategy == "atomic" else ("cshuffle", "tdm")
                )
                for persistent in (False, True)
            },
        )
        for c in cfgs:
            suffix = "_streamk"
            if c.reduction_strategy != "atomic":
                suffix += f"_{c.reduction_strategy}"
            self.assertIn(
                f"_comp_tdm_pc_{c.epilogue}_intrawave_False_False_False_{c.persistent}_",
                c.name,
            )
            self.assertTrue(c.name.endswith(suffix), c.name)


class TestStreamKTraitRejectReason(unittest.TestCase):
    def test_epilogue_follows_reduction(self):
        self.assertEqual(
            streamk_trait_reject_reason("compv3", "cshuffle", "atomic"), ""
        )
        self.assertIn(
            "cshuffle", streamk_trait_reject_reason("compv3", "default", "atomic")
        )
        self.assertEqual(
            streamk_trait_reject_reason("comp_tdm_pc", "cshuffle", "atomic"), ""
        )
        self.assertIn(
            "overwrites C", streamk_trait_reject_reason("comp_tdm_pc", "tdm", "atomic")
        )
        for strategy in ("linear", "tree"):
            self.assertEqual(
                streamk_trait_reject_reason("comp_tdm_pc", "tdm", strategy), ""
            )
            self.assertEqual(
                streamk_trait_reject_reason("comp_tdm_pc", "cshuffle", strategy), ""
            )
            self.assertTrue(streamk_trait_reject_reason("compv3", "default", strategy))

    def test_comp_async_not_supported(self):
        self.assertIn(
            "not supported for stream_k",
            streamk_trait_reject_reason("comp_async", "cshuffle", "linear"),
        )

    def test_tdm_pads_and_unknown_strategy(self):
        self.assertEqual(
            streamk_trait_reject_reason(
                "comp_tdm_pc", "cshuffle", "linear", pads=(True, False, False)
            ),
            TDM_PAD_REJECT_REASON,
        )
        self.assertEqual(
            streamk_trait_reject_reason(
                "compv3", "cshuffle", "linear", pads=(True,) * 3
            ),
            "",
        )
        self.assertIn(
            "reduction_strategy", streamk_trait_reject_reason("compv3", "cshuffle", "x")
        )

    def test_gfx1250_gate_for_stream_k(self):
        def reason(pipeline, epilogue, persistent=False, **kw):
            return gfx1250_pipeline_reject_reason(
                "gfx1250",
                pipeline,
                epilogue,
                "intrawave",
                num_waves=4,
                warp_tile_k=32,
                dtype_a="fp16",
                dtype_b="fp16",
                layout="rcr",
                variant_supported=True,
                variant_name="stream_k",
                persistent=persistent,
                pads=(False, False, False),
                streamk=True,
                **kw,
            )

        for epilogue in ("cshuffle", "tdm"):
            for persistent in (False, True):
                self.assertEqual(reason("comp_tdm_pc", epilogue, persistent), "")
        self.assertIn("not supported for stream_k", reason("comp_async", "cshuffle"))


class TestGemmUtilsSweepGate(unittest.TestCase):
    @classmethod
    def setUpClass(cls):
        try:
            import gemm_utils
        except Exception as exc:  # pragma: no cover - environment dependent
            raise unittest.SkipTest(f"gemm_utils not importable: {exc}")
        cls.gate = staticmethod(gemm_utils._gfx1250_pipeline_supported)

    def _ok(
        self,
        pipe,
        epi="cshuffle",
        arch="gfx1250",
        sched="intrawave",
        persist=False,
        waves=(2, 2, 1),
        variant="standard",
        **kw,
    ):
        return self.gate(pipe, sched, epi, persist, *waves, arch, variant, **kw)

    def test_legacy_passthrough(self):
        for arch in ("gfx942", "gfx950", "gfx1250"):
            self.assertTrue(self._ok("compv3", arch=arch))
            self.assertTrue(self._ok("compv4", arch=arch, sched="interwave"))

    def test_tdm_rules(self):
        self.assertTrue(self._ok("comp_tdm", "tdm"))
        self.assertTrue(self._ok("comp_tdm", "tdm", variant="batched"))
        self.assertTrue(self._ok("comp_tdm_v2", "tdm"))
        self.assertFalse(self._ok("comp_tdm", "tdm", arch="gfx950"))
        self.assertFalse(self._ok("comp_tdm", "cshuffle"))
        self.assertFalse(self._ok("comp_tdm", "tdm", persist=True))
        self.assertFalse(self._ok("comp_tdm", "tdm", sched="interwave"))
        for variant in ("multi_d", "grouped", "multi_abd"):
            self.assertFalse(self._ok("comp_tdm", "tdm", variant=variant), variant)
        # Stream-K takes comp_tdm_pc with either epilogue, persistent or not; the
        # epilogue is checked per reduction strategy by streamk_trait_reject_reason.
        for epi in ("tdm", "cshuffle"):
            for persist in (False, True):
                self.assertTrue(
                    self._ok("comp_tdm_pc", epi, persist=persist, variant="stream_k"),
                    (epi, persist),
                )
        self.assertFalse(self._ok("comp_tdm_v2", "tdm", waves=(4, 2, 1)))
        self.assertFalse(self._ok("compv3", "tdm"))

    def test_tdm_pc_rules(self):
        self.assertTrue(self._ok("comp_tdm_pc", "tdm"))
        self.assertTrue(self._ok("comp_tdm_pc", "tdm", waves=(4, 2, 1)))
        # BatchedGemmKernel arms the producer/consumer named barriers.
        self.assertTrue(self._ok("comp_tdm_pc", "tdm", variant="batched"))
        # Plain GEMM also takes cshuffle (split-K), still not batched or persistent.
        self.assertTrue(self._ok("comp_tdm_pc", "cshuffle"))
        self.assertFalse(self._ok("comp_tdm_pc", "cshuffle", variant="batched"))
        self.assertFalse(self._ok("comp_tdm_pc", "cshuffle", persist=True))
        self.assertFalse(self._ok("comp_tdm_pc", "default"))
        self.assertFalse(self._ok("comp_tdm_pc", "tdm", arch="gfx950"))
        self.assertFalse(self._ok("comp_tdm_pc", "tdm", persist=True))
        self.assertFalse(self._ok("comp_tdm_pc", "tdm", sched="interwave"))
        self.assertFalse(self._ok("comp_tdm_pc", "tdm", waves=(1, 2, 2)))
        self.assertTrue(self._ok("comp_tdm_pc", "tdm", tile_mn=(256, 128)))
        self.assertFalse(self._ok("comp_tdm_pc", "tdm", tile_mn=(256, 256)))
        self.assertTrue(
            self._ok("comp_tdm_pc", "tdm", waves=(4, 2, 1), tile_mn=(256, 256))
        )
        self.assertTrue(self._ok("comp_tdm", "tdm", tile_mn=(256, 256)))

    def _async(self, *args, **kw):
        return self._ok("comp_async", *args, pad_m=True, pad_n=True, pad_k=True, **kw)

    def test_comp_async_rules(self):
        self.assertTrue(self._async())
        self.assertTrue(self._async(persist=True))
        self.assertTrue(self._async(variant="batched"))
        self.assertFalse(self._async(arch="gfx942"))
        for variant in ("multi_d", "grouped", "multi_abd", "stream_k"):
            self.assertFalse(self._async(variant=variant), variant)
        self.assertFalse(self._async(sched="interwave"))
        self.assertFalse(self._async("tdm"))
        self.assertFalse(self._async("default"))
        self.assertFalse(self._async("cshuffle", sched="interwave"))

    def test_tdm_pad_rule(self):
        for pipe in TDM_PIPELINES:
            self.assertTrue(
                self._ok(pipe, "tdm", pad_m=False, pad_n=False, pad_k=False)
            )
            for pad in ("pad_m", "pad_n", "pad_k"):
                self.assertFalse(self._ok(pipe, "tdm", **{pad: True}), (pipe, pad))
        # comp_async requires full padding; legacy pipelines are unaffected.
        self.assertTrue(self._async())
        self.assertFalse(self._ok("comp_async"))
        for pad in ("pad_m", "pad_n", "pad_k"):
            kw = {"pad_m": True, "pad_n": True, "pad_k": True, pad: False}
            self.assertFalse(self._ok("comp_async", **kw), pad)
            self.assertTrue(self._ok("compv3", **kw), pad)
        self.assertTrue(self._ok("compv3", pad_m=True, pad_n=True, pad_k=True))

    def test_comp_async_layout_rule(self):
        self.assertTrue(self._async(layout="rcr"))
        self.assertTrue(self._async(layout=""))
        for layout in ("rrr", "crr", "ccr"):
            self.assertFalse(self._async(layout=layout), layout)
            self.assertTrue(self._ok("comp_tdm", "tdm", layout=layout), layout)
            self.assertTrue(self._ok("compv3", layout=layout), layout)

    def test_comp_async_8bit_warp_tile_k_rule(self):
        for dt in ("fp8", "bf8"):
            self.assertFalse(self._async(dtype=dt, warp_tile_k=64), dt)
            self.assertTrue(self._async(dtype=dt, warp_tile_k=128), dt)
            self.assertTrue(self._ok("compv3", dtype=dt, warp_tile_k=64), dt)
        self.assertTrue(self._async(dtype="fp16", warp_tile_k=32))
        self.assertTrue(self._async(dtype="", warp_tile_k=0))

    def test_expand_sweep_tdm_unpadded(self):
        import gemm_utils

        cfg = json.loads(json.dumps(TestUnifiedCodegenGolden.CONFIG))
        cfg["trait_config"]["pad_m"] = [False, True]
        cfg["trait_config"]["pad_n"] = [False, True]
        cfg["trait_config"]["pad_k"] = [False, True]
        # expand_sweep reads the Tile Engine {"values": [...]} schema.
        cfg = {
            section: {k: {"values": v} for k, v in entries.items()}
            for section, entries in cfg.items()
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            rcr = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
            rrr = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rrr")
        tdm = [c for c in rcr if c.pipeline in TDM_PIPELINES]
        self.assertTrue(tdm)
        for c in tdm:
            self.assertEqual((c.pad_m, c.pad_n, c.pad_k), (False, False, False))
        pads = {(c.pad_m, c.pad_n, c.pad_k) for c in rcr if c.pipeline == "comp_async"}
        self.assertEqual(pads, {(True, True, True)})
        self.assertFalse(any(c.pipeline == "comp_async" for c in rrr))
        self.assertTrue(any(c.pipeline == "comp_tdm" for c in rrr))
        self.assertTrue(any(c.pipeline == "comp_tdm_pc" for c in rcr))

    def test_expand_sweep_applies_codegen_lds_limit(self):
        # fp16 rcr 256x128x128 on 4x2x1 waves needs 104416B per LDS slot: it fits
        # comp_tdm's two slots but not comp_tdm_pc's four (81920B each), which
        # the codegen's ArchFilter rejects. expand_sweep must drop it too, or it
        # requests a header the codegen never emits.
        import gemm_utils

        tile = dict(
            tile_m=[256],
            tile_n=[128],
            tile_k=[128],
            warp_m=[4],
            warp_n=[2],
            warp_k=[1],
            warp_tile_m=[16],
            warp_tile_n=[16],
            warp_tile_k=[32],
        )
        trait = dict(
            pipeline=["comp_tdm", "comp_tdm_pc"],
            epilogue=["tdm"],
            scheduler=["intrawave"],
            pad_m=[False],
            pad_n=[False],
            pad_k=[False],
            persistent=[False],
        )
        cfg = {
            "tile_config": {k: {"values": v} for k, v in tile.items()},
            "trait_config": {k: {"values": v} for k, v in trait.items()},
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "fp16", "rcr")
        self.assertEqual({c.pipeline for c in got}, {"comp_tdm"})


class TestExpandSweepGfx1250Waves(unittest.TestCase):
    def test_compv3_offers_eight_waves(self):
        # The 8-warp compv3 miscompile (#11161) was fixed in C++ (#11175), and a gfx12
        # build without CK_TILE_USE_WMMA fails a static_assert instead of running wrong.
        import gemm_utils

        tile = {
            "tile_m": [128],
            "tile_n": [128],
            "tile_k": [64],
            "warp_m": [2, 4],
            "warp_n": [2, 4],
            "warp_k": [1],
            "warp_tile_m": [16],
            "warp_tile_n": [16],
            "warp_tile_k": [32],
        }
        trait = {
            "pipeline": ["compv3", "compv5"],
            "epilogue": ["cshuffle"],
            "scheduler": ["intrawave"],
            "pad_m": [True],
            "pad_n": [True],
            "pad_k": [True],
            "persistent": [False],
        }
        cfg = {
            "tile_config": {k: {"values": v} for k, v in tile.items()},
            "trait_config": {k: {"values": v} for k, v in trait.items()},
        }
        with tempfile.TemporaryDirectory() as td:
            path = Path(td) / "cfg.json"
            path.write_text(json.dumps(cfg))
            got = gemm_utils.expand_sweep(str(path), "gfx1250", "bf16", "rcr")
        waves = {(c.wave_m, c.wave_n, c.wave_k) for c in got if c.pipeline == "compv3"}
        self.assertTrue({(2, 4, 1), (4, 2, 1)} <= waves, waves)
        self.assertFalse(any(c.pipeline == "compv5" for c in got))


_CPP_PROBE = r"""
#include "ck_tile/dispatcher/arch_specs_generated.hpp"
#include "ck_tile/dispatcher/kernel_key.hpp"
#include <cstdio>
#include <string>
using namespace ck_tile::dispatcher;
using arch_specs::GpuArch;

// Existing enumerator values must not move (serialized keys depend on them).
static_assert(static_cast<int>(Pipeline::Mem) == 0, "");
static_assert(static_cast<int>(Pipeline::CompV3) == 3, "");
static_assert(static_cast<int>(Pipeline::PreShuffleV2) == 8, "");
static_assert(static_cast<int>(Pipeline::Wavelet) == 9, "");
static_assert(static_cast<int>(Pipeline::CompAsync) == 10, "");
static_assert(static_cast<int>(Pipeline::CompTDMV1) == 11, "");
static_assert(static_cast<int>(Pipeline::CompTDMV2) == 12, "");
static_assert(static_cast<int>(Pipeline::CompTDMPC) == 13, "");
static_assert(static_cast<int>(Pipeline::PreShuffleTDM) == 14, "");
static_assert(static_cast<int>(Pipeline::CompTDMRA) == 15, "");
static_assert(static_cast<int>(Epilogue::CShuffle) == 2, "");
static_assert(static_cast<int>(Epilogue::BiasActivation) == 5, "");
static_assert(static_cast<int>(Epilogue::Tdm) == 6, "");

int main()
{
    int fails = 0;
#define CHECK(c) do { if(!(c)) { std::printf("FAIL: %s\n", #c); ++fails; } } while(0)
    CHECK(to_string(Pipeline::CompAsync) == "comp_async");
    CHECK(to_string(Pipeline::CompTDMV1) == "comp_tdm");
    CHECK(to_string(Pipeline::CompTDMV2) == "comp_tdm_v2");
    CHECK(to_string(Pipeline::CompTDMPC) == "comp_tdm_pc");
    CHECK(to_string(Pipeline::CompTDMRA) == "comp_tdm_ra");
    CHECK(to_string(Epilogue::Tdm) == "tdm");
    CHECK(string_to_pipeline("comp_async") == Pipeline::CompAsync);
    CHECK(string_to_pipeline("comp_tdm") == Pipeline::CompTDMV1);
    CHECK(string_to_pipeline("comp_tdm_v2") == Pipeline::CompTDMV2);
    CHECK(string_to_pipeline("comp_tdm_pc") == Pipeline::CompTDMPC);
    CHECK(string_to_pipeline("comp_tdm_ra") == Pipeline::CompTDMRA);
    CHECK(string_to_pipeline("compv3") == Pipeline::CompV3);
    CHECK(string_to_pipeline("no_such_pipeline") == Pipeline::Mem);
    CHECK(string_to_epilogue("tdm") == Epilogue::Tdm);
    CHECK(string_to_epilogue("cshuffle") == Epilogue::CShuffle);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_1250, Pipeline::CompTDMV1) == 163840);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_1250, Pipeline::CompTDMV2) == 163840);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_1250, Pipeline::CompAsync) == 163840);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_1250, Pipeline::CompTDMPC) == 81920);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_942, Pipeline::CompTDMPC) == 16384);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_1250, Pipeline::CompTDMRA) == 81920);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_942, Pipeline::CompTDMRA) == 16384);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_950, Pipeline::CompTDMV1) == 81920);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_942, Pipeline::CompTDMV1) == 32768);
    CHECK(arch_specs::get_lds_capacity(GpuArch::GFX_942, Pipeline::CompV3) ==
          arch_specs::get_lds_capacity(GpuArch::GFX_942, Pipeline::Mem));
    CHECK(arch_specs::is_trait_unsupported(Pipeline::CompTDMV1, Epilogue::Tdm, Scheduler::Interwave));
    CHECK(arch_specs::is_trait_unsupported(Pipeline::CompAsync, Epilogue::CShuffle, Scheduler::Interwave));
    CHECK(!arch_specs::is_trait_unsupported(Pipeline::CompTDMV1, Epilogue::Tdm, Scheduler::Intrawave));
    CHECK(arch_specs::is_trait_unsupported(Pipeline::CompTDMPC, Epilogue::Tdm, Scheduler::Interwave));
    CHECK(!arch_specs::is_trait_unsupported(Pipeline::CompTDMPC, Epilogue::Tdm, Scheduler::Intrawave));
    CHECK(arch_specs::is_trait_unsupported(Pipeline::CompTDMRA, Epilogue::Tdm, Scheduler::Interwave));
    CHECK(!arch_specs::is_trait_unsupported(Pipeline::CompTDMRA, Epilogue::Tdm, Scheduler::Intrawave));
    // A non-default comp_tdm_pc ring follows the vector widths, as pipeline_ring_suffix().
    KernelKey key{};
    key.algorithm.pipeline = Pipeline::CompTDMPC;
    const std::string base = key.encode_identifier();
    CHECK(base.find("_s") == std::string::npos);
    key.algorithm.num_slots   = 2;
    key.algorithm.publish_lag = 1;
    CHECK(key.encode_identifier() == base + "_s2l1");
    KernelKey other = key;
    other.algorithm.publish_lag = 0;
    CHECK(!(key == other));
    // A non-default comp_tdm_ra ring spells its RunAhead with "r".
    KernelKey ra{};
    ra.algorithm.pipeline = Pipeline::CompTDMRA;
    const std::string ra_base = ra.encode_identifier();
    CHECK(ra_base.find("comp_tdm_ra") != std::string::npos);
    CHECK(ra_base.find("_s") == std::string::npos);
    ra.algorithm.num_slots = 3;
    ra.algorithm.run_ahead = 2;
    CHECK(ra.encode_identifier() == ra_base + "_s3r2");
    KernelKey ra_other = ra;
    ra_other.algorithm.run_ahead = 1;
    CHECK(!(ra == ra_other));
    return fails == 0 ? 0 : 1;
}
"""


@unittest.skipIf(shutil.which("g++") is None, "g++ not available")
class TestCppEnums(unittest.TestCase):
    def test_enum_values_strings_and_lds(self):
        with tempfile.TemporaryDirectory() as td:
            src = Path(td) / "probe.cpp"
            exe = Path(td) / "probe"
            src.write_text(_CPP_PROBE)
            build = subprocess.run(
                ["g++", "-std=c++17", "-I", str(INCLUDE_DIR), str(src), "-o", str(exe)],
                capture_output=True,
                text=True,
            )
            self.assertEqual(build.returncode, 0, build.stderr)
            run = subprocess.run([str(exe)], capture_output=True, text=True)
            self.assertEqual(run.returncode, 0, run.stdout + run.stderr)


if __name__ == "__main__":
    unittest.main()
