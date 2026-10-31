# Copyright Advanced Micro Devices, Inc., or its affiliates.
# SPDX-License-Identifier: MIT

"""Choose LDS layouts that reduce segment conflicts on gfx1250.

LDS has five 64 KiB segments and two read ports, one per SIMD pair. The ports
conflict when they read the same segment in a cycle. Interleaving separates
parts of an operand across segments to reduce these conflicts.

A0/A1 and B0/B1 denote parts of matrix data (components). Ping/pong denote the
two buffer copies of that data. All sizes and placement checks include padding.

Without TDMSplit: component order
--------------------------------
The ordinary order in one buffer is [A0][A1][B0][B1]. Interleaving uses:

  MIWaveGroup  Required vector width  Component order
  [2,2]        VWA == WaveTileA        [A0][B0][A1][B1], if B reads fit each component
                                      [A0][B whole][A1], if B reads cross components
  [4,1]        VWA == WaveTileA        [A0][B whole][A1]
  [1,4]        VWB == WaveTileB        [B0][A whole][B1]

For [2,2], B stays whole when splitting it would make a read cross a component
boundary; an odd WaveTileB can cause this. For [4,1]/[1,4], only the operand
spanning four waves is separated. The whole operand keeps its ordinary addressing.

Without TDMSplit: spacing and buffer copies
------------------------------------------
The component sizes and LDS base determine which of two layouts applies:

  Needs a gap to reach another segment ("aligned"):
    Insert a gap before component 1 to reach a 64 KiB boundary. Keep complete
    ping and pong blocks separate, each with the same internal order and gap.

  Packed order already reaches another segment ("tight"):
    Place each group's ping/pong copies together:
      split A/B: [A0 pair][B0 pair][gap if needed][A1 pair][B1 pair]
      B whole:   [A0 pair][B pair] [gap if needed][A1 pair]
      A whole:   [B0 pair][A pair] [gap if needed][B1 pair]
    Each pair is [ping][pong]. Recalculate spacing so A0/A1 (and split B0/B1)
    occupy disjoint segments in each phase: ping versus ping, pong versus pong.
    Different operands or phases may share segments.

For example, with [2,2] and split B, the first component spans fA + fB plus
MXSA0's slot when MXSA is M-split. The footprints include internal padding.
Insert a gap before A1 only if that complete span leaves A1 in A0's segment
(aligned). Otherwise the one-buffer order needs no gap (tight).
Pairing can still add gaps; "tight" describes the one-buffer order, not the final
ping/pong allocation. See paired_buffer_reason() for supported buffering settings.
StreamK and Persistent DataParallel use paired placement when supported and keep
separate ping/pong blocks otherwise, including when prefetching across persistent
tiles. Persistent MX kernels with shadow init keep separate blocks to avoid extra
SGPRs (see persistent_keeps_unpaired()).

Without MXSA M splitting, buffer placement for both MX scales is:
  Non-TDMSplit tight, with supported pairing:
    [all paired A/B data][MXSA ping][MXSA pong][MXSB ping][MXSB pong]
  Aligned, TDMSplit, or persistent without pairing:
    ping: [interleaved A/B data][MXSA][MXSB]
    pong: [interleaved A/B data][MXSA][MXSB]

On coarse [2,2] InMemorySwizzle layouts, MXSA can instead be loaded as two M
halves, one per SIMD pair, when TDM uses exactly two components. The halves
occupy separate segments and each contains all K scale groups. The builders
size the halves before assigning final A/B
bases and strides. With split B, each MXSA half follows its component's B
data; with whole B, it follows A instead and B keeps its baseline addressing.
Paired layouts preserve 256-byte alignment for every group. Auto compares the complete
split candidate with the ordinary layout's LDS reservation and falls back to
ordinary placement if the candidate needs more LDS.

With TDMSplit
-------------
Ping/pong remain separate blocks. The diagrams below show the read groups for
one buffer; | separates groups placed in different LDS segments. They show only
the operand being separated, omitting the other operand and any spacing gaps.

  [2,2], VWA == WaveTileA:
    [A0]                         | [A1]
    B is split or kept whole according to the B-read condition above.

  [2,2], VWA == WaveTileA/2 (portSplitA):
    Name four consecutive slices along A's M dimension A00, A01, A10, A11:
      Matrix order: [A00][A01][A10][A11]
      LDS order:    [A00][A10]      | [A01][A11]
    A00/A01 form the first half of A; A10/A11 form the second half. TDMSplit
    loads both halves, placing A00 with A10 and A01 with A11. The names label
    matrix slices, not waves or ping/pong buffers. B placement is omitted here.

  [4,1], VWA == WaveTileA (portSplitA):
      Matrix order: [A00][A01][A10][A11]
      Read by:       W0   W1   W2   W3
      LDS order:    [A00][A10]      | [A01][A11]
      Read by:       W0   W2       |  W1   W3
    Each wave reads one slice. Even waves read the left group through one port;
    odd waves read the right group through the other port.

  [4,1], VWA == WaveTileA/2 (componentSplit):
      Matrix order: [A00][A01][A10][A11]
      Read by:      W0/W1 W2/W3 W0/W1 W2/W3
      LDS order:    [A00][A10]      | [A01][A11]
      Read by:         W0/W1       |    W2/W3
    W0/W1 each read a different portion of A00 and A10; W2/W3 each read a
    different portion of A01 and A11. The data order is the same as above, but
    the smaller vector width changes which waves read it. Each group now serves
    both read ports: W0/W2 use one port, W1/W3 the other.

For [1,4], use the last two diagrams with A replaced by B, VWA by VWB, and
WaveTileA by WaveTileB; portSplitA becomes portSplitB. W0-W3 are the four waves.
Only the full and half WaveTile widths above are supported. The half-width case
requires TDMSplit; without it, [2,2]/[4,1] need VWA == WaveTileA and [1,4] needs
VWB == WaveTileB.

An MN-major B (see mn_major_b_requested) takes the [2,2] split layouts with each component a dense
[DepthU][MT1/2] block: wave-separated TDM loads one N half per component, and the transposed reads
use a K-row pitch of MT1/2.
"""

from ..Components.TDMFuse import tdmWaveComponents
from .Problem import isF16Accumulation

# gfx1250 LDS segment size (5 x 64 KiB segments).
SEG = 65536

def mn_major_b_requested(state):
    """An MN-major B is interleaved only on request, for f16 accumulation with an fp4 B read by ds_load_tr4_b64
    one tile per vector. Each component holds half of B's tiles, so MIWaveTile[1] must be even."""
    pt = state["ProblemType"]
    wtB = (state.get("MIWaveTile") or [0, 0])[1]
    return (state.get("LDSSegmentInterleave") == 1 and not state.get("UnrollMajorLDSB", True)
            and isF16Accumulation(pt) and pt.get("DataTypeB", pt["DataType"]).isFloat4()
            and bool(state.get("enableLDSTrB")) and state.get("VectorWidthB") == 1
            and wtB > 0 and wtB % 2 == 0)

def mn_major_b(kernel):
    """True when the applied interleave holds B as two dense MN-major components."""
    return kernel.get("LDSSegmentInterleave") == 1 and bool((kernel.get("LDSSegInterleaveOffsets") or {}).get("bMnMajor"))

def k_row_elems(kernel, tc):
    """Elements in one K row of tc's MN-major LDS tile, before padding: an interleaved MN-major B component is
    [DepthU][MT1/2]."""
    return kernel["MacroTile1"] // 2 if tc == "B" and mn_major_b(kernel) else kernel["MacroTile%s" % tc]

def _bpe(state, tc):
    # Float, not int -- fp4 is 0.5 B/elem; callers int() the byte counts. An fp4 operand widened after its LDS read
    # (f16 accumulation) is stored as fp4.
    pt = state["ProblemType"]
    dt = pt.get("DataType%s" % tc, pt["DataType"])
    if state.get("ConvertAfterDS") and dt.isFloat4():
        return dt.numBytes()
    return pt.get("MacDataType%s" % tc, pt["DataType"]).numBytes()

def _pad(x, blk, padElems, bpe):
    if blk == 0 or padElems == 0:
        return 0
    return int((x // blk) * padElems * bpe)

def _data_bytes(state, tc):
    numComp = state["NumWaves"] // 2
    mt = state["MacroTile0"] if tc == "A" else state["MacroTile1"]
    return int((mt // numComp) * state["DepthU"] * _bpe(state, tc))

def _footprint(state, tc):
    d = _data_bytes(state, tc)
    blk = state["LdsBlockSizePerPad%s" % tc]
    padElems = state["LdsPad%s" % tc]
    return d + _pad(d, blk, padElems, _bpe(state, tc))

def _tensor_footprint(state, tc):
    """Full baseline span, whose padding phase does not reset per component."""
    mt = state["MacroTile0"] if tc == "A" else state["MacroTile1"]
    d = int(mt * state["DepthU"] * _bpe(state, tc))
    blk = state["LdsBlockSizePerPad%s" % tc]
    padElems = state["LdsPad%s" % tc]
    return d + _pad(d, blk, padElems, _bpe(state, tc))

def _mx_scale_bases(state, mxsaStart):
    """MX scale-block LDS bases, placed after the interleaved A/B region. Returns
    (ldsBaseMXSA, ldsBaseMXSB, end)."""
    pt = state["ProblemType"]
    hasA = bool(pt.get("MXBlockA")) and not state.get("DirectToVgprMXSA")
    hasB = bool(pt.get("MXBlockB")) and not state.get("DirectToVgprMXSB")
    if not (hasA or hasB):
        return None, None, mxsaStart
    baseA = mxsaStart
    szA = int(state.get("LdsNumElementsAlignedMXSA", 0)) if hasA else 0
    baseB = baseA + szA
    szB = int(state.get("LdsNumElementsAlignedMXSB", 0)) if hasB else 0
    return (baseA if hasA else None), (baseB if hasB else None), baseB + szB


def _mxsa_half_layout(state, paired=False):
    """Size the MXSA M halves before placing any A/B components."""
    pt = state["ProblemType"]
    if (state.get("MIWaveGroup") != [2, 2] or state.get("NumWaves") != 4
            or state.get("LDSSegmentInterleave", -1) == 0
            or not pt.get("MXBlockA") or pt.get("MXBlockFreeA", 1) != 1
            or state.get("MXScaleFormat") != "InMemorySwizzle"
            or state.get("TDMFuse") or state.get("TDMSplit")
            or state.get("DirectToVgprMXSA") or not _coarse(state, "A")):
        return None
    # The TDM component IDs must map directly to the two reserved M-half slots.
    if tdmWaveComponents(state, "MXSA")[0] != 2:
        return None
    rawHalf = state["MacroTile0"] * (state["DepthU"] // pt["MXBlockA"]) // 2
    pad, block = state.get("LdsPadMXSA", 0), state.get("LdsBlockSizePerPadMXSA", 0)
    if pad < 0 or block < 0 or (pad > 0 and (block == 0 or rawHalf % block)):
        return None
    footprint = rawHalf + (rawHalf // block * pad if block else 0)
    if footprint <= 0:
        return None
    # Each new slot is aligned independently of the ordinary full MXSA buffer.
    slotBytes = _align_paired(footprint) if paired else ((footprint + 15) // 16) * 16
    return dict(mxsSplitA=True, mxsaHalfBytes=slotBytes,
                mxsaHalfFootprintBytes=footprint)


def _component_offsets(state, bWhole, portSplit):
    """Build final one-buffer A/B and scale positions together.

    Split B: [A0 B0 MXSA0] [A1 B1 MXSA1] [MXSB].
    Whole B: [A0 MXSA0 B]  [A1 MXSA1]    [MXSB].
    Aligned placement inserts a segment gap before A1. Each component reserves
    one independently aligned MXSA slot.
    """
    base = state["LdsOffsetA"]
    fA = _footprint(state, "A")
    fB = _tensor_footprint(state, "B") if bWhole else _footprint(state, "B")
    mxsa = _mxsa_half_layout(state)
    if mxsa and ((base + fA) % 16 or (fA + fB) % 16):
        mxsa = None
    half = mxsa["mxsaHalfBytes"] if mxsa else 0
    naturalStride = fA + fB + half
    # Use the complete first component for both selection and placement.
    aligned = (base + naturalStride) // SEG == base // SEG
    stride = _ceil_seg(base + naturalStride) - base if aligned else naturalStride
    offsets = dict(ldsBaseB=base + fA + (half if bWhole else 0),
                   writeStrideBytes=stride, footprintPacked=True)
    if bWhole:
        offsets["bBaseline"] = True
    if portSplit:
        offsets["portSplitA"] = True
    end = base + stride + fA + (0 if bWhole else fB)
    pt = state["ProblemType"]
    if mxsa:
        offsets.update(mxsa, ldsBaseMXSA=base + fA + (0 if bWhole else fB),
                       mxsaStrideBytes=stride)
        end += half
        if state.get("LDSSegmentBRotate"):
            # B's DS half selection uses its original logical component stride.
            offsets["readStrideBytesB"] = stride if aligned else fA + fB
    elif pt.get("MXBlockA") and not state.get("DirectToVgprMXSA"):
        offsets["ldsBaseMXSA"] = end
        end += int(state.get("LdsNumElementsAlignedMXSA", 0))
    if pt.get("MXBlockB") and not state.get("DirectToVgprMXSB"):
        offsets["ldsBaseMXSB"] = end
        end += int(state.get("LdsNumElementsAlignedMXSB", 0))
    return offsets, end, aligned

def _wactive(state, tc):
    return state["MIWaveGroup"][0] if tc == "A" else state["MIWaveGroup"][1]

def wave_tile_span(state, tc, vectorWidth=None):
    """Free-dimension span of one wave's complete instruction tile, in elements."""
    dim = "M" if tc == "A" else "N"
    vw = state["VectorWidth" + tc] if vectorWidth is None else vectorWidth
    # A rectangular instruction has multiple min(M,N)-wide tiIdx subtiles.
    # All of them belong to the wave, as do its blocks along this operand's axis.
    return state["MatrixInst" + dim] * state.get("MatrixInstB" + dim, 1) * vw

def _coarse(state, tc):
    # coarse = VW == WaveTile (the complete wave tile covers its component). W = waves on this tensor's dim
    # (MIWaveGroup[dim]); for [2,2] W == 2.
    W = _wactive(state, tc)
    mt = state["MacroTile0"] if tc == "A" else state["MacroTile1"]
    return W > 0 and wave_tile_span(state, tc) >= mt // W

def _port_split(state, tc):
    # VW==WaveTile/2 (2 vIdx per port) with TDMSplit. A smaller VW would need a >2-way split.
    if _coarse(state, tc) or not state.get("TDMSplit"):
        return False
    idx = 0 if tc == "A" else 1
    vw = state["VectorWidthA"] if tc == "A" else state["VectorWidthB"]
    wt = state["MIWaveTile"][idx]
    return vw > 0 and wt % vw == 0 and wt // vw == 2

def _port_split_a(state):
    return _port_split(state, "A")

def _b_readable(state):
    # True if B can be split across segments and still read correctly: either B covers a full
    # component (coarse), or its per-vIdx column span (vIdxColsB) divides compColsB evenly so no
    # single ds_load straddles the component boundary. WaveTileB=7 -> 112 % 32 != 0 -> False.
    numComp = state["NumWaves"] // 2
    if wave_tile_span(state, "B") >= state["MacroTile1"] // numComp:
        return True
    compColsB = state["MacroTile1"] // numComp
    vIdxColsB = state["MatrixInstN"] * state.get("MatrixInstBN", 1) * state["MIWaveGroup"][1] * state["VectorWidthB"]
    return vIdxColsB > 0 and compColsB % vIdxColsB == 0

def _no(reason):
    return {"applicable": False, "aligned": False, "offsets": None,
            "blockSpan": 0, "reason": reason}

def _ceil_seg(x):
    return ((x + SEG - 1) // SEG) * SEG

def _align_paired(x):
    # Preserve the 256-byte LDS bank phase when moving between copies.
    return ((x + 255) // 256) * 256

def aligned_budget_ok(blockSpan, numLdsBlk, naturalOffsetBlk, maxLDS):
    """Return (ok, per-buffer block) for the aligned branch: the block is the next power
    of two >= max(naturalOffsetBlk, blockSpan), valid only if double-buffering it fits MaxLDS."""
    if numLdsBlk != 2:
        return (False, None)
    offsetBlk = max(naturalOffsetBlk, blockSpan)
    if offsetBlk <= 0:
        return (False, None)
    roundup = 1 << (offsetBlk - 1).bit_length()   # next power of two
    if roundup * 2 > maxLDS:
        return (False, None)                      # total = roundup + blockSpan <= roundup*2
    return (True, roundup)

def _evaluate_asymmetric(state):
    # [4,1]/[1,4]: active tensor = the dim>1 one (A for [4,1], B for [1,4]); the other is shared.
    # split the active comps across segments; leave the shared one baseline (aBaseline/bBaseline).
    # numComp stays 2, so the load count is unchanged.
    activeTC = "A" if state["MIWaveGroup"][0] > 1 else "B"
    sharedTC = "B" if activeTC == "A" else "A"

    fAct     = _footprint(state, activeTC)
    fActData = _data_bytes(state, activeTC)
    sharedSpan = _tensor_footprint(state, sharedTC)
    base     = state["LdsOffsetA"]
    baselineKey = "bBaseline" if activeTC == "A" else "aBaseline"
    sharedBaseKey = "ldsBaseB" if activeTC == "A" else "ldsBaseA"

    def _build_offsets(stride):
        # active comp0 @ base, shared @ base+fAct; emit sites read ldsBase<tc>.
        o = {sharedBaseKey: base + fAct, "ldsBase%s" % activeTC: base,
             "writeStrideBytes": stride, "footprintPacked": True,
             baselineKey: True, "activeTC": activeTC}
        bMXSA, bMXSB, _ = _mx_scale_bases(state, base + 2 * fAct + sharedSpan)
        if bMXSA is not None: o["ldsBaseMXSA"] = bMXSA
        if bMXSB is not None: o["ldsBaseMXSB"] = bMXSB
        return o

    if state.get("TDMSplit"):
        if not (_coarse(state, activeTC) or _port_split(state, activeTC)):
            return _no("TDMSplit asymmetric: active VW must be WaveTile or WaveTile/2")
        # VW==WaveTile splits by read port; VW==WaveTile/2 can't (needs >2-way) so it splits by component.
        useCompAxis = _port_split(state, activeTC) and not _coarse(state, activeTC)
        splitKey = "componentSplit" if useCompAxis else ("portSplitA" if activeTC == "A" else "portSplitB")
        strideAct = fAct + sharedSpan
        c0end = (base + fActData - 1) // SEG
        c1 = (base + strideAct) // SEG
        if c1 > c0end:
            # shared block already separates the two ports into different segments; free.
            o = _build_offsets(strideAct)
            o[splitKey] = True
            return {"applicable": True, "aligned": False, "offsets": o,
                    "blockSpan": 0, "reason": "compaxis-asym" if useCompAxis else "portaxis-asym"}
        # port1 still shares port0's segment: pad it to the next segment boundary. Grows LDS.
        if state.get("PrefetchGlobalRead") != 2:        return _no(("compaxis-asym" if useCompAxis else "portaxis-asym") + ": both components fit one segment, aligned layout (LDS grows) needs PGR=2")
        if state.get("LDSSegmentInterleave", -1) == -1: return _no("auto: skip aligned (LDS growth)")
        pre = _ceil_seg(base + strideAct) - base
        o = _build_offsets(pre)
        o[splitKey] = True
        blockSpan = base + pre + fAct
        bMXSA, bMXSB, mxEnd = _mx_scale_bases(state, blockSpan)
        if bMXSA is not None: o["ldsBaseMXSA"] = bMXSA
        if bMXSB is not None: o["ldsBaseMXSB"] = bMXSB
        blockSpan = max(blockSpan, mxEnd)
        return {"applicable": True, "aligned": True, "offsets": o,
                "blockSpan": blockSpan,
                "reason": "compaxis-asym-aligned" if useCompAxis else "portaxis-asym-aligned"}

    # active must be coarse (VW == WaveTile).
    if not _coarse(state, activeTC):
        return _no("%s active: VW must be WaveTile (coarse)" % activeTC)

    # A active only (baseline puts A at base, B after A+scales -> [1,4] can't shortcut): baseline
    # already splits A0/A1 when comp0 data fits one segment and comp1 lands in the next.
    if activeTC == "A" and (base % SEG) + fActData <= SEG and (base + fAct) // SEG != base // SEG:
        return _no("baseline already separates A0/A1 into different segments "
                   "(A active; comp0 data within one segment)")

    # put the shared tensor between the two active comps. bcontig if that stride already crosses a
    # segment; else aligned (pad to the boundary).
    #   A active: [A0][B][A1] bBaseline    B active: [B0][A][B1] aBaseline
    strideAct = fAct + sharedSpan            # comp0 -> comp1 gap

    # comp0 can span 2 segments (unaligned base); comp1 must start past its last one.
    c0end = (base + fActData - 1) // SEG
    c1 = (base + strideAct) // SEG
    if c1 > c0end:
        # shared block already pushed comp1 to a new segment; free.
        return {"applicable": True, "aligned": False, "offsets": _build_offsets(strideAct),
                "blockSpan": 0, "reason": "bcontig-asym"}

    # smaller: pad comp1 to the next segment. grows LDS -> PGR1/PGR2 + force only.
    if state.get("PrefetchGlobalRead") not in (1, 2):
        return _no("bcontig-asym: aligned layout needs PGR=1 or 2")
    if state.get("LDSSegmentInterleave", -1) == -1: return _no("auto: skip aligned (LDS growth)")
    pre = _ceil_seg(base + strideAct) - base
    offsets = _build_offsets(pre)
    blockSpan = base + pre + fAct
    bMXSA, bMXSB, mxEnd = _mx_scale_bases(state, blockSpan)
    if bMXSA is not None: offsets["ldsBaseMXSA"] = bMXSA
    if bMXSB is not None: offsets["ldsBaseMXSB"] = bMXSB
    blockSpan = max(blockSpan, mxEnd)
    return {"applicable": True, "aligned": True, "offsets": offsets,
            "blockSpan": blockSpan, "reason": "bcontig-asym-aligned"}


def evaluate(state):
    pt = state["ProblemType"]
    # Tri-state knob: -1 = auto (default), 0 = force baseline, 1 = force on where applicable.
    # Auto takes only the no-trade-off tight branch; the LDS-growing aligned branch needs 1.
    mode = state.get("LDSSegmentInterleave", -1)
    if mode == 0:                                              return _no("parameter off")
    if tuple(state.get("ISA", ()))[:2] != (12, 5):             return _no("not gfx1250")
    if not (state.get("enableTDMA") and state.get("enableTDMB") and state["NumWaves"] > 1):
        return _no("not wave-separated TDM")
    if state.get("LocalSplitU", 1) > 1:
        return _no("LocalSplitU>1")
    mnB = not state.get("UnrollMajorLDSB") and mn_major_b_requested(state)
    if not state.get("UnrollMajorLDSA") or not (state.get("UnrollMajorLDSB") or mnB):
        # An MN-major B that fails only the even-tile rule gets its own reason: each of the two
        # components holds half of B's tiles, so an odd MIWaveTile[1] has no split.
        if not state.get("UnrollMajorLDSB") and mn_major_b_requested(dict(state, MIWaveTile=[0, 2])):
            return _no("MN-major B: needs an even MIWaveTile[1]")
        return _no("not unrollMajor")
    # DirectToVgpr operands are not in LDS, so segment placement does not apply.
    if state.get("DirectToVgprA") or state.get("DirectToVgprB"):
        return _no("DirectToVgpr operand not LDS-resident")
    # numComp==2 (NumWaves==4) restricts MIWaveGroup to {[2,2],[4,1],[1,4]}, all with even waves
    # per active dim. [2,2] interleaves both tensors; [4,1]/[1,4] have one active + one shared
    # tensor and are handled by _evaluate_asymmetric below.
    if state["NumWaves"] // 2 != 2:                             return _no("numComp!=2")
    if pt.get("Sparse"):
        return _no("sparse")
    # Subtile uses a separate codegen body; the emit path these offsets target runs only for
    # non-subtile kernels.
    if state.get("UseSubtileImpl"):                            return _no("subtile")
    # Needs double-buffering; 1LDSBuffer==1 breaks the assumed layout. Unresolved -1 is rejected too
    # (Solution.py resolves it later, then re-evaluates).
    if state.get("1LDSBuffer", 0) != 0:                         return _no("needs 1LDSBuffer==0")
    _dt = pt["DataType"]
    # fp8/fp4 cover mxf8/mxf4; MX scales are relocated as a trailing block (see _mx_scale_bases).
    if not (_dt.isBFloat16() or _dt.isHalf() or _dt.is8bitFloat() or _dt.isFloat4()):
        return _no("bf16/fp16/fp8/fp4 only")

    # [4,1]/[1,4]: exactly one MIWaveGroup dim is 1 -> one active + one shared tensor.
    wgM, wgN = state["MIWaveGroup"][0], state["MIWaveGroup"][1]
    if mnB and ([wgM, wgN] != [2, 2] or state.get("TDMSplit") or not _b_readable(state)):
        return _no("MN-major B: needs MIWaveGroup [2,2], no TDMSplit, and B reads within a component")
    if (wgM == 1) ^ (wgN == 1):
        return _evaluate_asymmetric(state)
    if [wgM, wgN] != [2, 2]:
        return _no("MIWaveGroup unsupported")

    # [2,2]: A must be coarse (VWA==WaveTileA) or port-split (VWA==WaveTileA/2, needs TDMSplit).
    _portSplit = _port_split_a(state)
    if not (_coarse(state, "A") or _portSplit):               return _no("A: VWA must be WaveTileA, or WaveTileA/2 with TDMSplit")

    bWhole = not _b_readable(state)
    offsets, end, aligned = _component_offsets(state, bWhole, _portSplit)
    if mnB:
        offsets["bMnMajor"] = True
    if aligned:
        # Auto retains its existing rule: segment gaps require an explicit request.
        if (state.get("PrefetchGlobalRead") != 2
                and (state.get("TDMSplit") or state.get("PrefetchGlobalRead") != 1)):
            reason = "bcontig: aligned layout needs" if bWhole else "aligned: needs"
            return _no(reason + " PGR=2 with TDMSplit, otherwise PGR=1 or 2")
        if mode == -1:
            return _no("auto: skip aligned (LDS growth)")
    if bWhole:
        reason = "bcontig-aligned" if aligned else "bcontig"
    else:
        reason = "aligned" if aligned else "tight"
    return {"applicable": True, "aligned": aligned, "offsets": offsets,
            "blockSpan": end if aligned else 0, "reason": reason}


def b_rotate_reason(state, persistent=False):
    """LDSSegmentBRotate gate. Returns None when B-rotate can be applied, else the reject reason.

    Validate the logical [2,2] split layout used by aligned and paired tight kernels.
    B's logical component stride stays in [64K, 128K), so LocalReadAddrB+h still selects
    half h. The physical component stride comes from the selected layout; a per-wave
    register delta bridges that distance and rotates odd waves' B reads. The accumulator halves are
    swapped back before the epilogue. Aligned kernels retain separate ping/pong blocks.
    """
    pt = state["ProblemType"]
    if tuple(state.get("ISA", ()))[:2] != (12, 5):            return "not gfx1250"
    if state.get("LDSSegmentInterleave") != 1:                return "needs LDSSegmentInterleave=1"
    o = state.get("LDSSegInterleaveOffsets") or {}
    for key in ("aBaseline", "bBaseline", "portSplitA", "portSplitB", "componentSplit"):
        if o.get(key):                                        return "LSI layout '%s' not supported" % key
    S = o.get("readStrideBytesB", o.get("writeStrideBytes", 0))
    if not (SEG <= S < 2 * SEG):                              return "component stride must be in [64K, 128K)"
    fB = _footprint(state, "B")
    baseB = o.get("ldsBaseB", 0)
    # LocalRead picks LocalReadAddrB+h by offset // 64K: half 0 must stay below 64K, half 1 below 128K.
    if fB > SEG or S + fB > 2 * SEG:                          return "B component reach exceeds the two 64K local-read registers"
    # pair 1's +1 = root - (S - 64K) must stay non-negative.
    if baseB < S - SEG:                                       return "ldsBaseB below S - 64K"
    if state.get("NumLdsBlk") != 2 or state.get("1LDSBuffer") != 0:
        return "needs 2 LDS buffers"
    if list(state["MIWaveGroup"]) != [2, 2] or state["NumWaves"] != 4 or state["WavefrontSize"] != 32:
        return "needs MIWaveGroup [2,2], 4 waves, wave32"
    fA = _footprint(state, "A")
    if fA > SEG:
        return "A component exceeds 64K"
    if not (state.get("enableTDMA") and state.get("enableTDMB")):
        return "needs wave-separated TDM for both operands"
    if state.get("PrefetchGlobalReadA", -1) != -1 or state.get("PrefetchGlobalReadB", -1) != -1:
        return "decoupled PrefetchGlobalReadA/B not supported"
    if state.get("PrefetchGlobalRead") not in (1, 2):          return "needs PrefetchGlobalRead=1 or 2"
    if state.get("ExpandPointerSwap"):                        return "needs ExpandPointerSwap=0"
    vwb, wtb = state["VectorWidthB"], state["MIWaveTile"][1]
    if vwb <= 0 or wtb % vwb != 0 or (wtb // vwb) % 2 != 0:
        return "MIWaveTile[1]/VectorWidthB must be even"
    if pt.get("MXBlockB"):
        # MXSB must follow the rotation. Supported only for the TileSpan wave-split layout with
        # one group (nV == 2): vIdx 0/1 scales sit in the lower/upper half-wave of one ds_load,
        # so pair 1 flips the half-wave select in LRA. MXSA needs nothing (A is not rotated).
        # TileSpan (LocalRead.getMxsTileSpanInfo) is gated on exactly gfx1250.
        if tuple(state.get("ISA", ())) != (12, 5, 0):         return "MX: needs ISA (12, 5, 0)"
        if state.get("DirectToVgprMXSB"):                     return "MX: DirectToVgprMXSB not supported"
        if state.get("MXScaleFormat") != "InMemorySwizzle":   return "MX: needs MXScaleFormat InMemorySwizzle"
        if state["MatrixInstN"] != state["WavefrontSize"] // 2:
            return "MX: needs MatrixInstN == WavefrontSize/2"
        if wtb // vwb != 2:                                   return "MX: needs MIWaveTile[1]/VectorWidthB == 2"
    if pt.get("Sparse"):                                      return "sparse not supported"
    # An MN-major B (bMnMajor) is read with ds_load_tr4_b64 and rotates by tile.
    for key in ("TDMSplit", "UseSubtileImpl", "DirectToVgprA", "DirectToVgprB", "DirectToLdsB",
                "enableLDSTrA", "enableLDSTrB", "UseDotInstruction", "UseCustomMainLoopSchedule",
                "PrefetchAcrossPersistent", "TDMFuse"):
        if key == "enableLDSTrB" and o.get("bMnMajor"):
            continue
        v = state.get(key)
        # -1 (auto) means unresolved/off for the tri-state knobs; only a positive value enables.
        if v is True or (isinstance(v, int) and v > 0):      return "%s not supported" % key
    if state.get("LocalSplitU", 1) > 1:                       return "LocalSplitU>1 not supported"
    if state.get("NumWaveSplitK", 1) > 1:                     return "NumWaveSplitK>1 not supported"
    if persistent:                                            return "persistent / StreamK not supported"
    return None


def paired_buffer_reason(state):
    """Limit general pairing to the existing two-buffer TDM emit path."""
    if state.get("LDSSegmentInterleave") != 1:
        return "segment interleave is not active"
    if state.get("NumLdsBlk") != 2 or state.get("1LDSBuffer") != 0:
        return "needs two LDS buffers"
    if state.get("PrefetchGlobalRead") not in (1, 2):
        return "needs PrefetchGlobalRead=1 or 2"
    if state.get("WavefrontSize") != 32:
        return "needs wave32"
    if state.get("PrefetchGlobalReadA", -1) != -1 or state.get("PrefetchGlobalReadB", -1) != -1:
        return "decoupled prefetch is not supported"
    for key in ("ExpandPointerSwap", "TDMSplit", "UseSubtileImpl", "DirectToVgprA",
                "DirectToVgprB", "DirectToLdsA", "DirectToLdsB", "enableLDSTrA",
                "enableLDSTrB", "UseDotInstruction", "UseCustomMainLoopSchedule",
                "PrefetchAcrossPersistent", "TDMFuse"):
        v = state.get(key)
        if v is True or (isinstance(v, int) and v > 0):
            return "%s is not supported" % key
    if state.get("LocalSplitU", 1) != 1 or state.get("NumWaveSplitK", 1) > 1:
        return "split-K LDS layout is not supported"
    return None


def persistent_keeps_unpaired(state):
    """Whether a persistent kernel keeps the interleave's separate ping/pong blocks.

    Pairing reserves a per-wave swap-mask SGPR for each descriptor set (A/B, and
    the MX scales). Persistent MX kernels with shadow init can already sit at the
    SGPR limit, so they keep the unpaired layout instead of failing code generation.
    """
    pt = state["ProblemType"]
    return bool(pt["MXBlockA"] or pt["MXBlockB"]) and not state["ForceDisableShadowInit"]


def paired_buffer_offsets(state, isolate_operands=False):
    """Pair existing read groups without changing their membership or read order.

    Separate corresponding component footprints in each buffer phase, equally for
    A and B. Cross-phase and cross-operand accesses may still share segments.
    A contiguous operand retains its original padding phase. Optional operand isolation
    adds segment gaps between every pair; reject it if the complete layout does not
    fit. The caller includes pairedUsedBytes in the normal LDS budget calculation.
    bufferStride<tensor> is the ping-to-pong distance within a pair;
    writeStrideBytes is the component-0-to-component-1 distance. Both distances
    and group bases are 256-byte aligned without changing internal padding.
    Include supported MXSA M-half placement before checking the final LDS size.
    """
    original = state["LDSSegInterleaveOffsets"]
    offsets = {key: original[key] for key in (
        "footprintPacked", "aBaseline", "bBaseline", "activeTC", "portSplitA",
        "portSplitB", "componentSplit") if key in original}
    base = _align_paired(state["LdsOffsetA"])
    shared = "A" if offsets.get("aBaseline") else ("B" if offsets.get("bBaseline") else None)
    active = "B" if shared == "A" else "A"
    fActive = _footprint(state, active)
    fOther = _tensor_footprint(state, shared) if shared else _footprint(state, "B")
    dActive = _align_paired(fActive)
    dOther = _align_paired(fOther)
    other = shared or "B"
    activeEnd = base + dActive + fActive
    mxsa = _mxsa_half_layout(state, paired=True) if active == "A" else None
    half = mxsa["mxsaHalfBytes"] if mxsa else 0
    # With whole B, place the scale pair immediately after A0, before B.
    # With split B, it follows B0. Both orders repeat at component stride S.
    mxsaBase = _align_paired(activeEnd) if mxsa and shared else None
    otherStart = mxsaBase + 2 * half if mxsa and shared else activeEnd
    otherBase = _ceil_seg(otherStart) if isolate_operands else _align_paired(otherStart)
    otherEnd = otherBase + dOther + fOther
    if mxsa and not shared:
        mxsaBase = _align_paired(otherEnd)
    componentEnd = mxsaBase + 2 * half if mxsa and not shared else otherEnd
    stride = _align_paired(componentEnd - base)
    if isolate_operands:
        stride = _ceil_seg(base + stride) - base
    else:
        # Use one component stride for both operands. Each component-1 ping/pong
        # copy must start past the last segment occupied by the matching
        # component-0 copy, including padding. The natural stride already keeps
        # the intervening pair out of the way; only add a gap if needed.
        splitPairs = [(base, fActive, dActive)]
        if not shared:
            splitPairs.append((otherBase, fOther, dOther))
        if mxsa:
            splitPairs.append((mxsaBase, mxsa["mxsaHalfFootprintBytes"], half))
        for pairBase, size, bufferStride in splitPairs:
            for buffer in (0, 1):
                start = pairBase + buffer * bufferStride
                end = start + size  # Exclusive: an exact segment boundary is reusable.
                nextSegmentStart = _ceil_seg(end)
                stride = max(stride, nextSegmentStart - start)
    stride = _align_paired(stride)
    offsets["ldsBase" + active] = base
    offsets["ldsBase" + other] = otherBase
    offsets["bufferStride" + active] = dActive
    offsets["bufferStride" + other] = dOther
    if state.get("LDSSegmentBRotate"):
        # Preserve logical DS half selection while VGPR bases bridge the common
        # physical stride. Rotation changes read order, never data placement.
        offsets["readStrideBytesB"] = original.get("readStrideBytesB", original["writeStrideBytes"])
    offsets["writeStrideBytes"] = stride
    end = base + stride + dActive + fActive if shared else otherBase + stride + dOther + fOther
    if mxsa:
        offsets.update(mxsa, ldsBaseMXSA=mxsaBase, bufferStrideMXSA=half,
                       mxsaStrideBytes=stride)
        end = mxsaBase + stride + 2 * half
    for tc in ("MXSA", "MXSB"):
        if "ldsBase" + tc in original and not (tc == "MXSA" and mxsa):
            size = int(state["LdsNumElementsAligned" + tc])
            scaleBase = _align_paired(end)
            offsets["ldsBase" + tc] = scaleBase
            offsets["bufferStride" + tc] = _align_paired(size)
            end = scaleBase + offsets["bufferStride" + tc] + size
    offsets["pairedBuffers"] = True
    offsets["pairedUsedBytes"] = end
    offsets["pairedOperandIsolation"] = isolate_operands
    # Narrow [2,2] B reads reach both components through DS immediates. Reserve
    # only reachable 64 KiB windows, rather than allocating registers for gaps.
    if state.get("LDSSegmentBRotate"):
        # B rotation uses two logical halves, not the ordinary physical windows.
        offsets.pop("readAddressWindowsB", None)
    elif not shared and state["MIWaveGroup"] == [2, 2] and not _coarse(state, "B"):
        windows = set(range((fOther - 1)//SEG + 1))
        windows.update(range(stride//SEG, (stride + fOther - 1)//SEG + 1))
        offsets["readAddressWindowsB"] = sorted(windows)
    return offsets if offsets["pairedUsedBytes"] <= state["MaxLDS"] else None


def paired_buffer_layout_reason(state, offsets):
    """Validate physical placement, independently of the read-conflict policy.

    Footprints retain their existing internal padding. This checks every ping/pong
    start (including MX scales), allocation overlap and the LDS budget;
    it does not replace the TDM padding-phase or per-instruction read checks.
    """
    regions = []
    for tc in ("A", "B", "MXSA", "MXSB"):
        if tc in ("A", "B"):
            shared = offsets.get("aBaseline" if tc == "A" else "bBaseline", False)
            size = _tensor_footprint(state, tc) if shared else _footprint(state, tc)
            components = 1 if shared else 2
        else:
            if "ldsBase" + tc not in offsets:
                continue
            split = tc == "MXSA" and offsets.get("mxsSplitA", False)
            size = offsets["mxsaHalfBytes"] if split else int(state["LdsNumElementsAligned" + tc])
            components = 2 if split else 1
        base = offsets.get("ldsBase" + tc, state["LdsOffsetA"])
        bufferStride = offsets["bufferStride" + tc]
        if size <= 0:
            return "%s has an empty paired footprint" % tc
        for component in range(components):
            for buffer in (0, 1):
                stride = offsets["mxsaStrideBytes"] if tc == "MXSA" and offsets.get("mxsSplitA") else offsets["writeStrideBytes"]
                start = base + component * stride + buffer * bufferStride
                name = "%s%d %s" % (tc, component, "pong" if buffer else "ping")
                if start < 0 or start % 256:
                    return "%s start %d is not a non-negative 256-byte-aligned address" % (name, start)
                regions.append((start, start + size, name))
    regions.sort()
    for left, right in zip(regions, regions[1:]):
        if left[1] > right[0]:
            return "%s overlaps %s" % (left[2], right[2])
    if regions[-1][1] > state["MaxLDS"]:
        return "paired layout exceeds MaxLDS"
    if regions[-1][1] > offsets["pairedUsedBytes"]:
        return "paired footprint exceeds pairedUsedBytes"
    return None
