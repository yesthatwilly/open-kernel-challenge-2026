# okc: problem=muse_attention_decode
"""Gated attention decode with the pre-attention chain fused into one Triton kernel.

SGLang's path launches, before FlashAttention 3: the fused QK-norm (+RoPE), a k cast to FP8,
a v cast to FP8, the cache store and a q cast to FP8. On sliding-window layers at decode the
attention itself moves under a megabyte, so those launches are most of the time. This kernel
does all five in one launch: per (token, head) it RMS-normalizes q or k, applies interleaved
RoPE when the layer has it, and writes q as FP8 for FA3 and the new k and v rows as FP8 into
the cache (divided by the cache scales). FA3 and the output norm x sigmoid(gate) are SGLang's.
"""

from typing import TypedDict

import torch
import triton
import triton.language as tl
from sgl_kernel.flash_attn import flash_attn_with_kvcache

from sglang.kernels.ops.muse_spark_v12.norm_gate import rms_norm_gate


class Config(TypedDict):
    batch: int            # B
    q_len: int            # L: 1 for decode, 8 for a speculative verify block (causal inside it)
    num_q_heads: int      # Hq: 16 per GPU under TP8
    num_kv_heads: int     # Hkv: 2; each serves Hq / Hkv query heads
    head_dim: int         # 64
    page_size: int        # 1 in the scored cases (as SGLang serves Muse on H200), 64 in some tests
    window: int           # 2048 on sliding-window layers (a token and the 2,047 before it); 0 = all
    rope_theta: float     # 500000 on sliding-window layers; 0 = no RoPE
    qk_scale_factor: float
    sm_scale: float       # 1/8
    kv_scale: float       # the cache scales' value: 1 in the scored cases (SGLang leaves them unset)


class Inputs(TypedDict):
    qkv: torch.Tensor          # bfloat16 [B, L, (2*Hq + 2*Hkv)*64], 2304 under tp8: per token q (Hq*64),
                               # then the block's keys before norm and RoPE (Hkv*64), values
                               # (Hkv*64) and the output gate's logits (Hq*64)
    positions: torch.Tensor    # int64 [B*L], each new token's position (seq_lens[b] + i)
    cache_loc: torch.Tensor    # int64 [B*L], each new token's flat cache row (page * page_size + offset)
    cache_seqlens: torch.Tensor  # int32 [B], seq_lens + L: what each request attends over
    cu_seqlens_q: torch.Tensor   # int32 [B+1], 0, L, 2L, ...: the block's query offsets
    scheduler_metadata: torch.Tensor | None  # int32, FA3's tile schedule (get_scheduler_metadata) on
                                             # full-attention decode steps, else None
    k_cache: torch.Tensor     # float8_e4m3fn [pages, page_size, Hkv, 64], written in place
    v_cache: torch.Tensor     # float8_e4m3fn [pages, page_size, Hkv, 64], written in place
    k_scale: torch.Tensor     # float32 [], key = e4m3 * k_scale
    v_scale: torch.Tensor     # float32 [], value = e4m3 * v_scale
    page_table: torch.Tensor  # int32 [B, max_pages], physical page of each logical page (-1 unused)
    seq_lens: torch.Tensor    # int32 [B], cached tokens per request; the block starts at this position
    config: Config


RMS_EPS = 1e-5
FP8 = torch.float8_e4m3fn
_INV_FREQ = {}


def _inv_freq(theta: float, d: int, device) -> torch.Tensor:
    """[d/2] float32 theta^(-2i/d), built exactly as the reference builds it; cached per theta."""
    key = (theta, d, str(device))
    cache = _INV_FREQ.get(key)
    if cache is None:
        cache = _INV_FREQ[key] = 1.0 / (theta ** (torch.arange(0, d, 2, device=device).float() / d))
    return cache


@triton.jit
def _pre_attention_kernel(
    qkv_ptr, pos_ptr, loc_ptr, inv_freq_ptr, k_scale_ptr, v_scale_ptr,
    q_out_ptr, k_cache_ptr, v_cache_ptr,
    qkv_stride,
    HQ: tl.constexpr, HKV: tl.constexpr, D: tl.constexpr, ROPE: tl.constexpr, EPS: tl.constexpr,
    PAIRED: tl.constexpr, G: tl.constexpr,
):
    """One program per (token, head). Heads 0..HQ-1 are queries; HQ..HQ+HKV-1 are the new keys,
    whose program also stores the matching value head. The q and k heads are contiguous in the
    fused row, so head h starts at h*D for both. When PAIRED, q_out is the zero-padded
    [tokens, HQ, 2*D] FA3 query: query h writes its D values into the half (h // G) % 2 (its KV
    head's half of the paired 128-byte row) and D FP8 zeros into the other half, so the program
    owns its whole padded row and every byte of it is written on every call."""
    t = tl.program_id(0)
    h = tl.program_id(1)
    HALF: tl.constexpr = D // 2
    i = tl.arange(0, HALF)
    even = 2 * i
    odd = 2 * i + 1

    row = qkv_ptr + t.to(tl.int64) * qkv_stride
    base = row + h * D
    xe = tl.load(base + even).to(tl.float32)
    xo = tl.load(base + odd).to(tl.float32)

    # Scaleless RMSNorm over the head's D entries.
    ss = tl.sum(xe * xe, axis=0) + tl.sum(xo * xo, axis=0)
    r = 1.0 / tl.sqrt(ss / D + EPS)
    xe = xe * r
    xo = xo * r

    if ROPE:
        # Interleaved (GPT-J) RoPE: pair (2i, 2i+1) rotates by pos * theta^(-2i/d).
        p = tl.load(pos_ptr + t).to(tl.float32)
        ang = p * tl.load(inv_freq_ptr + i)
        c = tl.cos(ang)
        s = tl.sin(ang)
        ye = xe * c - xo * s
        yo = xe * s + xo * c
        xe = ye
        xo = yo

    if h < HQ:
        # Query, rounded to FP8 E4M3 for FA3 (the 5.473 factor is folded into the softmax scale).
        if PAIRED:
            half = (h // G) % 2
            qrow = q_out_ptr + (t.to(tl.int64) * HQ + h) * (2 * D)
            out = qrow + half * D
            zj = tl.arange(0, D)
            tl.store(qrow + (1 - half) * D + zj, tl.zeros([D], dtype=tl.float32).to(tl.float8e4nv))
        else:
            out = q_out_ptr + (t.to(tl.int64) * HQ + h) * D
        tl.store(out + even, xe.to(tl.float8e4nv))
        tl.store(out + odd, xo.to(tl.float8e4nv))
    else:
        kh = h - HQ
        loc = tl.load(loc_ptr + t).to(tl.int64)
        k_scale = tl.load(k_scale_ptr)
        v_scale = tl.load(v_scale_ptr)
        kout = k_cache_ptr + (loc * HKV + kh) * D
        tl.store(kout + even, (xe / k_scale).to(tl.float8e4nv))
        tl.store(kout + odd, (xo / k_scale).to(tl.float8e4nv))
        # The value head: no norm, no RoPE, just the scale and the FP8 cast.
        j = tl.arange(0, D)
        v = tl.load(row + (HQ + HKV + kh) * D + j).to(tl.float32)
        vout = v_cache_ptr + (loc * HKV + kh) * D
        tl.store(vout + j, (v / v_scale).to(tl.float8e4nv))


@triton.jit
def _paired_norm_gate_kernel(
    attn_ptr, qkv_ptr, out_ptr,
    attn_stride_t, attn_stride_h, qkv_stride,
    HQ: tl.constexpr, HKV: tl.constexpr, D: tl.constexpr, G: tl.constexpr, EPS: tl.constexpr,
):
    """Full-layer epilogue for the paired path, one program per (token, query head): reads head
    h's own half (h // G) % 2 of FA3's [tokens, HQ, 2*D] output (the other half is the other KV
    head's P@V and is never read), applies the scaleless RMSNorm (eps inside the sqrt of the mean
    of D squares, fp32) times sigmoid(gate) and stores bf16 into the [tokens, HQ*D] output."""
    t = tl.program_id(0)
    h = tl.program_id(1)
    j = tl.arange(0, D)
    half = (h // G) % 2
    src = attn_ptr + t.to(tl.int64) * attn_stride_t + h * attn_stride_h + half * D
    x = tl.load(src + j).to(tl.float32)
    r = 1.0 / tl.sqrt(tl.sum(x * x, axis=0) / D + EPS)
    gate = tl.load(qkv_ptr + t.to(tl.int64) * qkv_stride + (HQ + 2 * HKV) * D + h * D + j)
    gate = gate.to(tl.float32)
    y = x * r * tl.sigmoid(gate)
    tl.store(out_ptr + (t.to(tl.int64) * HQ + h) * D + j, y.to(tl.bfloat16))


def kernel_fn(data: Inputs) -> torch.Tensor:
    cfg = data["config"]
    batch, length = cfg["batch"], cfg["q_len"]
    hq, hkv, d = cfg["num_q_heads"], cfg["num_kv_heads"], cfg["head_dim"]
    tokens = batch * length
    qkv = data["qkv"].reshape(tokens, -1)
    device = qkv.device
    theta = cfg["rope_theta"]

    k_cache, v_cache = data["k_cache"], data["v_cache"]
    window = cfg["window"]
    # Full layers: pair the two KV heads of each token into one 128-byte FP8 row (heads 2s and
    # 2s+1 are adjacent halves of it) so FA3 gathers one row per token instead of two. Each
    # query sits in its own head's half of a zero-padded 128-wide query, so the zero half adds
    # exactly 0 to every logit; FA3 maps query head h to super-head h // (2G), which keeps the
    # original grouping. The pre-attention kernel writes that padded query directly and a Triton
    # epilogue reads each head's half of FA3's output, so no pad/un-pad copies are launched. This
    # one config-only predicate selects both the query layout and the FA3/epilogue branch.
    # Companion paired-heads-launch-cleanup-ab-tune-batch-gate: pair only at batch > 1 (batch 1
    # keeps the unpaired path, where pairing lost 27-35%).
    paired = window == 0 and hkv % 2 == 0 and batch > 1
    g = hq // hkv
    q = torch.empty((tokens, hq, 2 * d if paired else d), dtype=FP8, device=device)
    inv_freq = _inv_freq(theta, d, device) if theta else data["k_scale"]  # unused when ROPE is off
    _pre_attention_kernel[(tokens, hq + hkv)](
        qkv, data["positions"], data["cache_loc"], inv_freq, data["k_scale"], data["v_scale"],
        q, k_cache, v_cache,
        qkv.stride(0),
        HQ=hq, HKV=hkv, D=d, ROPE=bool(theta), EPS=RMS_EPS, PAIRED=paired, G=g,
        num_warps=1,
    )

    # The judge's scheduler_metadata was built for the unpaired geometry, so on the paired path
    # it is not passed (FA3 builds its own schedule from the paged lengths).
    if paired:
        s = hkv // 2
        pages, page_size = k_cache.shape[0], k_cache.shape[1]
        k_attn = k_cache.view(pages, page_size, s, 2 * d)
        v_attn = v_cache.view(pages, page_size, s, 2 * d)
        q_attn = q
        attn_heads = s
        metadata = None
    else:
        k_attn, v_attn, q_attn = k_cache, v_cache, q
        attn_heads = hkv
        metadata = data["scheduler_metadata"]
    descale = {}
    if cfg["kv_scale"] != 1.0:
        descale = dict(k_descale=data["k_scale"].reshape(1, 1).expand(batch, attn_heads),
                       v_descale=data["v_scale"].reshape(1, 1).expand(batch, attn_heads))
    out = flash_attn_with_kvcache(
        q=q_attn,
        k_cache=k_attn,
        v_cache=v_attn,
        page_table=data["page_table"],
        cache_seqlens=data["cache_seqlens"],
        cu_seqlens_q=data["cu_seqlens_q"],
        max_seqlen_q=length,
        softmax_scale=cfg["sm_scale"] * cfg["qk_scale_factor"],
        causal=True,
        window_size=(window - 1, 0) if window else (-1, -1),
        scheduler_metadata=metadata,
        **descale,
    )
    if isinstance(out, tuple):
        out = out[0]
    if paired:
        # Each query's own half of FA3's 128-wide output, normalized and gated in one launch.
        attn = out.view(tokens, hq, 2 * d)
        o = torch.empty((tokens, hq * d), dtype=torch.bfloat16, device=device)
        _paired_norm_gate_kernel[(tokens, hq)](
            attn, qkv, o,
            attn.stride(0), attn.stride(1), qkv.stride(0),
            HQ=hq, HKV=hkv, D=d, G=g, EPS=RMS_EPS,
            num_warps=1,
        )
        return o.view(batch, length, hq * d)
    gate = qkv[:, (hq + 2 * hkv) * d:]
    o = rms_norm_gate(out.reshape(tokens, hq * d).to(torch.bfloat16), gate, None, head_dim=d, eps=RMS_EPS,
                      has_norm=True)
    return o.view(batch, length, hq * d)
