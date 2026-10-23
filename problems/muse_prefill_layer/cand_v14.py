# okc: problem=muse_prefill_layer
"""Muse Spark Open prefill layer: v14, TMA indexed NVFP4 experts.

Dense projections on cuBLAS (as SGLang), FA3 attention on Hopper (a Triton fallback elsewhere),
Triton for every elementwise/norm/routing step (fused), and the routed experts either as
SGLang's Marlin W4A16 (small token counts) or, for large token counts, the touched experts'
NVFP4 weights expanded exactly to BF16 (e2m1 x e4m3 is exact in BF16; the FP32 per-expert
scale is applied in FP32 after the GEMM) followed by DeepGEMM's grouped BF16 GEMM.
"""

import math

import torch
import triton
import triton.language as tl

HIDDEN = 8192
D_EXPERT = 4096
N_EXPERTS = 256
LOCAL_EXPERTS = 32
TOP_K = 8
HQ, HKV, HEAD_DIM = 16, 2, 64
Q_SIZE, KV_SIZE = HQ * HEAD_DIM, HKV * HEAD_DIM
UNPOOL_SLICE = 1024
RMS_EPS = 1e-5
POST_EPS = 1e-8
ROUTER_MULT = 0.1767766952966369
ROPE_THETA = 500_000.0
ROPE_POSITIONS = 1 << 18
DG_ALIGN = 128            # DeepGEMM's M alignment for the contiguous (psum) grouped layout
BIG_TOKENS = 2048         # at or above this many tokens the experts use dequant + DeepGEMM

IS_HOPPER = torch.cuda.is_available() and torch.cuda.get_device_capability() == (9, 0)


# ----------------------------------------------------------------------------------------------
# Triton kernels
# ----------------------------------------------------------------------------------------------

@triton.jit
def _qk_prep_kernel(qkv_ptr, pos_ptr, loc_ptr, cs_ptr, q_out_ptr, kc_ptr, vc_ptr, ks_ptr, vs_ptr,
                    T, HAS_ROPE: tl.constexpr, BT: tl.constexpr):
    """Per token: RMS-norm q (16 heads) and k (2 heads) over 64, interleaved RoPE, q -> FP8,
    k / k_scale and v / v_scale -> FP8 into the paged cache at cache_loc."""
    pid = tl.program_id(0)
    t = pid * BT + tl.arange(0, BT)
    tm = t < T
    i = tl.arange(0, 32)
    hq = tl.arange(0, 16)
    hk = tl.arange(0, 2)
    row = qkv_ptr + t.to(tl.int64)[:, None, None] * 2304
    # q: [BT, 16, 32] even / odd
    qoff = hq[None, :, None] * 64 + 2 * i[None, None, :]
    m3 = tm[:, None, None]
    qe = tl.load(row + qoff, mask=m3, other=0.0).to(tl.float32)
    qo = tl.load(row + qoff + 1, mask=m3, other=0.0).to(tl.float32)
    koff = 1024 + hk[None, :, None] * 64 + 2 * i[None, None, :]
    ke = tl.load(row + koff, mask=m3, other=0.0).to(tl.float32)
    ko = tl.load(row + koff + 1, mask=m3, other=0.0).to(tl.float32)
    qr = tl.rsqrt((tl.sum(qe * qe, 2) + tl.sum(qo * qo, 2)) / 64.0 + 1e-5)
    kr = tl.rsqrt((tl.sum(ke * ke, 2) + tl.sum(ko * ko, 2)) / 64.0 + 1e-5)
    qe = qe * qr[:, :, None]
    qo = qo * qr[:, :, None]
    ke = ke * kr[:, :, None]
    ko = ko * kr[:, :, None]
    if HAS_ROPE:
        p = tl.load(pos_ptr + t, mask=tm, other=0).to(tl.int64)
        c = tl.load(cs_ptr + p[:, None, None] * 64 + i[None, None, :], mask=m3, other=1.0)
        s = tl.load(cs_ptr + p[:, None, None] * 64 + 32 + i[None, None, :], mask=m3, other=0.0)
        qe, qo = qe * c - qo * s, qe * s + qo * c
        ke, ko = ke * c - ko * s, ke * s + ko * c
    qdst = q_out_ptr + t.to(tl.int64)[:, None, None] * 1024 + qoff
    tl.store(qdst, qe.to(tl.float8e4nv), mask=m3)
    tl.store(qdst + 1, qo.to(tl.float8e4nv), mask=m3)
    ks = tl.load(ks_ptr)
    vs = tl.load(vs_ptr)
    loc = tl.load(loc_ptr + t, mask=tm, other=0).to(tl.int64)
    kdst = kc_ptr + loc[:, None, None] * 128 + hk[None, :, None] * 64 + 2 * i[None, None, :]
    tl.store(kdst, (ke / ks).to(tl.float8e4nv), mask=m3)
    tl.store(kdst + 1, (ko / ks).to(tl.float8e4nv), mask=m3)
    d = tl.arange(0, 64)
    v = tl.load(row + 1152 + hk[None, :, None] * 64 + d[None, None, :], mask=m3, other=0.0).to(tl.float32)
    vdst = vc_ptr + loc[:, None, None] * 128 + hk[None, :, None] * 64 + d[None, None, :]
    tl.store(vdst, (v / vs).to(tl.float8e4nv), mask=m3)


@triton.jit
def _attn_fwd_kernel(q_ptr, kc_ptr, vc_ptr, pt_ptr, seq_ptr, o_ptr, ks_ptr, vs_ptr, scale,
                     L, max_pages, PAGE: tl.constexpr, WINDOW: tl.constexpr,
                     BQ: tl.constexpr, BN: tl.constexpr):
    """Fallback prefill attention (non-Hopper): BQ query tokens x 8 grouped heads of one KV
    head per program, keys from the paged FP8 cache (the block's own keys are already there)."""
    qb = tl.program_id(0)
    bh = tl.program_id(1)
    b = bh // 2
    h = bh % 2
    M: tl.constexpr = BQ * 8
    rows = tl.arange(0, M)
    qi = qb * BQ + rows // 8
    g = rows % 8
    qmask = qi < L
    seq = tl.load(seq_ptr + b)
    qpos = seq + qi
    d = tl.arange(0, 64)
    tok = (b * L + qi).to(tl.int64)
    q = tl.load(q_ptr + tok[:, None] * 1024 + (h * 8 + g)[:, None] * 64 + d[None, :],
                mask=qmask[:, None], other=0.0).to(tl.bfloat16)
    ks = tl.load(ks_ptr)
    vs = tl.load(vs_ptr)
    sc = scale * ks * 1.4426950408889634
    m_i = tl.full([M], -float("inf"), tl.float32)
    l_i = tl.zeros([M], tl.float32)
    acc = tl.zeros([M, 64], tl.float32)
    q_lo = seq + qb * BQ
    q_hi = tl.minimum(seq + qb * BQ + BQ - 1, seq + L - 1)
    if WINDOW > 0:
        start = tl.maximum(q_lo - WINDOW + 1, 0)
    else:
        start = 0
    start = (start // BN) * BN
    for j0 in range(start, q_hi + 1, BN):
        j = j0 + tl.arange(0, BN)
        jm = j <= q_hi
        pg = tl.load(pt_ptr + b * max_pages + j // PAGE, mask=jm, other=0)
        r = (pg.to(tl.int64) * PAGE + j % PAGE)
        k = tl.load(kc_ptr + r[:, None] * 128 + h * 64 + d[None, :], mask=jm[:, None], other=0.0).to(tl.bfloat16)
        v = tl.load(vc_ptr + r[:, None] * 128 + h * 64 + d[None, :], mask=jm[:, None], other=0.0).to(tl.bfloat16)
        s = tl.dot(q, tl.trans(k)) * sc
        vis = (j[None, :] <= qpos[:, None]) & jm[None, :]
        if WINDOW > 0:
            vis = vis & (j[None, :] > qpos[:, None] - WINDOW)
        s = tl.where(vis, s, -float("inf"))
        m_new = tl.maximum(m_i, tl.max(s, 1))
        m_use = tl.where(m_new == -float("inf"), 0.0, m_new)
        alpha = tl.exp2(m_i - m_use)
        p = tl.exp2(s - m_use[:, None])
        l_i = l_i * alpha + tl.sum(p, 1)
        acc = acc * alpha[:, None] + tl.dot(p.to(tl.bfloat16), v)
        m_i = m_new
    out = acc / l_i[:, None] * vs
    tl.store(o_ptr + tok[:, None] * 1024 + (h * 8 + g)[:, None] * 64 + d[None, :], out.to(tl.bfloat16),
             mask=qmask[:, None])


@triton.jit
def _norm_gate_kernel(x_ptr, qkv_ptr, o_ptr, R, BR: tl.constexpr):
    """o[t, h] = rms(x[t, h]) * sigmoid(gate[t, h]); rows are (token, head) pairs."""
    pid = tl.program_id(0)
    r = pid * BR + tl.arange(0, BR)
    rm = r < R
    d = tl.arange(0, 64)
    x = tl.load(x_ptr + r.to(tl.int64)[:, None] * 64 + d[None, :], mask=rm[:, None], other=0.0).to(tl.float32)
    t = r // 16
    h = r % 16
    gt = tl.load(qkv_ptr + t.to(tl.int64)[:, None] * 2304 + 1280 + h[:, None] * 64 + d[None, :],
                 mask=rm[:, None], other=0.0).to(tl.float32)
    x = x * tl.rsqrt(tl.sum(x * x, 1) / 64.0 + 1e-5)[:, None]
    y = x * tl.sigmoid(gt)
    tl.store(o_ptr + r.to(tl.int64)[:, None] * 64 + d[None, :], y.to(tl.bfloat16), mask=rm[:, None])


@triton.jit
def _boundary_kernel(branch_ptr, stream_ptr, new_stream_ptr, out_ptr, post_w_ptr, alpha_ptr, beta_ptr,
                     pre_w_ptr, HAS_POST_W: tl.constexpr, H: tl.constexpr):
    """new = alpha * stream + beta * rms(branch * post_w, 1e-8); out = rms(new, 1e-5) * pre_w."""
    row = tl.program_id(0).to(tl.int64)
    c = tl.arange(0, H)
    x = tl.load(branch_ptr + row * H + c).to(tl.float32)
    if HAS_POST_W:
        x = x * tl.load(post_w_ptr + c)
    x = x * tl.rsqrt(tl.sum(x * x, 0) / H + 1e-8)
    s = tl.load(stream_ptr + row * H + c)
    new = tl.load(alpha_ptr + c) * s + tl.load(beta_ptr + c) * x
    tl.store(new_stream_ptr + row * H + c, new)
    y = new * tl.rsqrt(tl.sum(new * new, 0) / H + 1e-5) * tl.load(pre_w_ptr + c)
    tl.store(out_ptr + row * H + c, y.to(tl.bfloat16))


@triton.jit
def _routing_kernel(logits_ptr, bias_ptr, ls_ptr, ids_ptr, w_ptr, slot_e_ptr, slot_pos_ptr, counts_ptr):
    """Sigmoid scores (hi + lo logits), biased top-8, renormalized weights; each route to a local
    expert gets a slot in its expert's segment (atomic count)."""
    t = tl.program_id(0).to(tl.int64)
    e = tl.arange(0, 256)
    lg = tl.load(logits_ptr + t * 512 + e) + tl.load(logits_ptr + t * 512 + 256 + e)
    s = tl.sigmoid(lg * 0.1767766952966369)
    b = s + tl.load(bias_ptr + e)
    ls = tl.load(ls_ptr)
    kk = tl.arange(0, 8)
    sel_ids = tl.zeros([8], tl.int32)
    sel_s = tl.zeros([8], tl.float32)
    for k in tl.static_range(8):
        mx = tl.max(b, 0)
        idx = tl.min(tl.where(b == mx, e, 256), 0)
        sk = tl.sum(tl.where(e == idx, s, 0.0), 0)
        sel_ids = tl.where(kk == k, idx, sel_ids)
        sel_s = tl.where(kk == k, sk, sel_s)
        b = tl.where(e == idx, -float("inf"), b)
    w = sel_s / (tl.sum(sel_s, 0) + 1e-15)
    tl.store(ids_ptr + t * 8 + kk, sel_ids)
    tl.store(w_ptr + t * 8 + kk, w)
    loc = (sel_ids - ls + 256) % 256
    is_local = loc < 32
    pos = tl.atomic_add(counts_ptr + loc, tl.full([8], 1, tl.int32), mask=is_local)
    tl.store(slot_e_ptr + t * 8 + kk, tl.where(is_local, loc, -1))
    tl.store(slot_pos_ptr + t * 8 + kk, tl.where(is_local, pos, 0))


@triton.jit
def _offsets_kernel(counts_ptr, starts_ptr, psum_ptr, ALIGN: tl.constexpr):
    e = tl.arange(0, 32)
    c = tl.load(counts_ptr + e)
    padded = ((c + ALIGN - 1) // ALIGN) * ALIGN
    incl = tl.cumsum(padded, 0)
    st = incl - padded
    tl.store(starts_ptr + e, st)
    tl.store(psum_ptr + e, st + c)


@triton.jit
def _gather_norm_kernel(p_ptr, w_ptr, slot_e_ptr, slot_pos_ptr, starts_ptr, a_ptr, row_of_ptr, D: tl.constexpr):
    """xn = rms(pooled[t]) * (1 + w); copy it to each of the token's local-route rows."""
    t = tl.program_id(0).to(tl.int64)
    c = tl.arange(0, D)
    x = tl.load(p_ptr + t * D + c).to(tl.float32)
    x = (x * tl.rsqrt(tl.sum(x * x, 0) / D + 1e-5) * tl.load(w_ptr + c)).to(tl.bfloat16)
    for k in tl.static_range(8):
        e = tl.load(slot_e_ptr + t * 8 + k)
        if e >= 0:
            r = tl.load(starts_ptr + e) + tl.load(slot_pos_ptr + t * 8 + k)
            tl.store(a_ptr + r.to(tl.int64) * D + c, x)
            tl.store(row_of_ptr + t * 8 + k, r)
        else:
            tl.store(row_of_ptr + t * 8 + k, -1)


@triton.jit
def _e2m1(code):
    """e2m1 code (int32, 0-15) -> fp32 value. e == 0: 0.5 * m; else 2^(e-1) * (1 + m/2)."""
    mag = code & 7
    ex = mag >> 1
    man = mag & 1
    nrm = (((ex + 126) << 23) | (man << 22)).to(tl.float32, bitcast=True)
    v = tl.where(ex == 0, man.to(tl.float32) * 0.5, nrm)
    return tl.where((code & 8) != 0, -v, v)


@triton.jit
def _dequant_kernel(q_ptr, sf_ptr, out_ptr, counts_ptr, ROWS: tl.constexpr, K: tl.constexpr, BR: tl.constexpr,
                    BKB: tl.constexpr):
    """BF16 copy of expert e's NVFP4 rows (e2m1 * e4m3 block scale, exact); untouched experts skip."""
    e = tl.program_id(0)
    if tl.load(counts_ptr + e) == 0:
        return
    r = tl.program_id(1) * BR + tl.arange(0, BR)
    base = e.to(tl.int64) * ROWS + r.to(tl.int64)
    for j0 in tl.static_range(0, K // 2, BKB):
        j = j0 + tl.arange(0, BKB)
        p = tl.load(q_ptr + base[:, None] * (K // 2) + j[None, :]).to(tl.int32)
        sf = tl.load(sf_ptr + base[:, None] * (K // 16) + j[None, :] // 8).to(tl.float8e4nv, bitcast=True).to(tl.float32)
        w = tl.join(_e2m1(p & 15) * sf, _e2m1(p >> 4) * sf).reshape(BR, 2 * BKB)
        k = 2 * j0 + tl.arange(0, 2 * BKB)
        tl.store(out_ptr + base[:, None] * K + k[None, :], w.to(tl.bfloat16))


@triton.jit
def _swiglu_kernel(h_ptr, out_ptr, starts_ptr, counts_ptr, gs_ptr, BR: tl.constexpr, D: tl.constexpr):
    """inter = silu(gs * gate) * (gs * up) for expert e's rows (h = [gate | up], unscaled)."""
    e = tl.program_id(0)
    n = tl.load(counts_ptr + e)
    r0 = tl.program_id(1) * BR
    if r0 >= n:
        return
    st = tl.load(starts_ptr + e)
    r = r0 + tl.arange(0, BR)
    rm = r < n
    rows = (st + r).to(tl.int64)
    gs = tl.load(gs_ptr + e)
    c = tl.arange(0, D)
    g = tl.load(h_ptr + rows[:, None] * (2 * D) + c[None, :], mask=rm[:, None], other=0.0).to(tl.float32) * gs
    u = tl.load(h_ptr + rows[:, None] * (2 * D) + D + c[None, :], mask=rm[:, None], other=0.0).to(tl.float32) * gs
    g = g.to(tl.bfloat16).to(tl.float32)
    u = u.to(tl.bfloat16).to(tl.float32)
    y = g * tl.sigmoid(g) * u
    tl.store(out_ptr + rows[:, None] * D + c[None, :], y.to(tl.bfloat16), mask=rm[:, None])


@triton.jit
def _combine_kernel(y_ptr, row_of_ptr, slot_e_ptr, w_ptr, gs_ptr, pw_ptr, out_ptr, D: tl.constexpr):
    """out[t] = sum_k w[t,k] * rms(gs_e * y[row] * (1 + w_post), 1e-8) over the token's local routes."""
    t = tl.program_id(0).to(tl.int64)
    c = tl.arange(0, D)
    pw = tl.load(pw_ptr + c)
    acc = tl.zeros([D], tl.float32)
    for k in tl.static_range(8):
        r = tl.load(row_of_ptr + t * 8 + k)
        if r >= 0:
            e = tl.load(slot_e_ptr + t * 8 + k)
            y = (tl.load(y_ptr + r.to(tl.int64) * D + c).to(tl.float32) * tl.load(gs_ptr + e)).to(tl.bfloat16).to(tl.float32) * pw
            y = y * tl.rsqrt(tl.sum(y * y, 0) / D + 1e-8)
            acc += tl.load(w_ptr + t * 8 + k) * y
    tl.store(out_ptr + t * D + c, acc.to(tl.bfloat16))


@triton.jit
def _pre_expert_norm_kernel(p_ptr, w_ptr, out_ptr, D: tl.constexpr):
    t = tl.program_id(0).to(tl.int64)
    c = tl.arange(0, D)
    x = tl.load(p_ptr + t * D + c).to(tl.float32)
    tl.store(out_ptr + t * D + c, (x * tl.rsqrt(tl.sum(x * x, 0) / D + 1e-5) * tl.load(w_ptr + c)).to(tl.bfloat16))


# ----------------------------------------------------------------------------------------------
# prepare
# ----------------------------------------------------------------------------------------------

def _residual_coefficients(gate):
    w = gate.float() / 0.3
    beta = torch.sigmoid(w)
    alpha = torch.sqrt(torch.clamp(torch.sigmoid(-w) * (1.0 + beta), min=1e-3))
    return alpha.contiguous(), beta.contiguous()


def prepare_base(weights):
    dev = weights["qkv_gate"].device
    router = weights["router"].float()
    hi = router.to(torch.bfloat16)
    lo = (router - hi.float()).to(torch.bfloat16)
    inv_freq = 1.0 / (ROPE_THETA ** (torch.arange(0, 64, 2, dtype=torch.float, device=dev) / 64))
    freqs = torch.arange(ROPE_POSITIONS, dtype=torch.float, device=dev)[:, None] * inv_freq[None, :]
    a1, b1 = _residual_coefficients(weights["attn_residual_gate"])
    a2, b2 = _residual_coefficients(weights["ffn_residual_gate"])
    st = {
        "qkv": weights["qkv_gate"].contiguous(),
        "o": weights["o"].contiguous(),
        "pooler": weights["pooler"].contiguous(),
        "unpooler": weights["unpooler"].contiguous(),
        "router_cat": torch.cat([hi, lo], 0).contiguous(),        # [512, 8192]: hi rows then lo rows
        "router_bias": weights["router_bias"].float().contiguous(),
        "cos_sin": torch.cat([freqs.cos(), freqs.sin()], -1).contiguous(),
        "a1": a1, "b1": b1, "a2": a2, "b2": b2,
        "pre_ffn": (1.0 + weights["pre_ffn_norm"].float()).contiguous(),
        "pre_expert": (1.0 + weights["pre_expert_norm"].float()).contiguous(),
        "post_expert": (1.0 + weights["post_expert_norm"].float()).contiguous(),
        "post_ffn": (1.0 + weights["post_ffn_norm"].float()).contiguous(),
        "next_pre_attn": (1.0 + weights["next_pre_attn_norm"].float()).contiguous(),
        "w13": weights["w13"].contiguous(), "w13_sf": weights["w13_sf"].view(torch.uint8).contiguous(),
        "w13_gs": weights["w13_gs"].float().contiguous(),
        "w2": weights["w2"].contiguous(), "w2_sf": weights["w2_sf"].view(torch.uint8).contiguous(),
        "w2_gs": weights["w2_gs"].float().contiguous(),
    }
    # SGLang binds the post-expert norm's (1 + w) in BF16 for its Marlin finalize.
    st["post_expert_bf16"] = st["post_expert"].to(torch.bfloat16)
    torch.cuda.synchronize()
    return st


# ----------------------------------------------------------------------------------------------
# kernel_fn
# ----------------------------------------------------------------------------------------------

def _attention(data, q8, st):
    cfg = data["config"]
    tokens, batch, length = cfg["tokens"], cfg["batch"], cfg["q_len"]
    window = cfg["window"]
    if IS_HOPPER:
        from sgl_kernel.flash_attn import flash_attn_with_kvcache
        descale = {}
        if cfg["kv_scale"] != 1.0:
            descale = dict(k_descale=data["k_scale"].reshape(1, 1).expand(batch, HKV),
                           v_descale=data["v_scale"].reshape(1, 1).expand(batch, HKV))
        out = flash_attn_with_kvcache(
            q=q8.view(tokens, HQ, HEAD_DIM), k_cache=data["k_cache"], v_cache=data["v_cache"],
            page_table=data["page_table"], cache_seqlens=data["cache_seqlens"],
            cu_seqlens_q=data["cu_seqlens_q"], max_seqlen_q=length,
            softmax_scale=cfg["sm_scale"] * cfg["qk_scale_factor"], causal=True,
            window_size=(window - 1, 0) if window else (-1, -1),
            scheduler_metadata=data["scheduler_metadata"], **descale)
        if isinstance(out, tuple):
            out = out[0]
        return out.reshape(tokens, Q_SIZE)
    out = torch.empty((tokens, Q_SIZE), dtype=torch.bfloat16, device=q8.device)
    BQ = 16
    _attn_fwd_kernel[(triton.cdiv(length, BQ), batch * HKV)](
        q8, data["k_cache"], data["v_cache"], data["page_table"], data["seq_lens"], out,
        data["k_scale"], data["v_scale"], cfg["sm_scale"] * cfg["qk_scale_factor"],
        length, data["page_table"].shape[1], PAGE=cfg["page_size"], WINDOW=window, BQ=BQ, BN=64,
        num_warps=8, num_stages=2)
    return out


def kernel_fn(data, st):
    cfg = data["config"]
    T = cfg["tokens"]
    dev = data["attn_input"].device
    x = data["attn_input"]
    # --- attention ---
    qkv = torch.mm(x, st["qkv"].t())                                   # [T, 2304] bf16
    q8 = torch.empty((T, Q_SIZE), dtype=torch.float8_e4m3fn, device=dev)
    BT = 4
    _qk_prep_kernel[(triton.cdiv(T, BT),)](
        qkv, data["positions"], data["cache_loc"], st["cos_sin"], q8,
        data["k_cache"], data["v_cache"],
        data["k_scale"], data["v_scale"], T, HAS_ROPE=bool(cfg["rope_theta"]), BT=BT, num_warps=4)
    attn = _attention(data, q8, st)                                    # [T, 1024] bf16
    o_in = torch.empty((T, Q_SIZE), dtype=torch.bfloat16, device=dev)
    BRG = 32
    _norm_gate_kernel[(triton.cdiv(T * HQ, BRG),)](attn, qkv, o_in, T * HQ, BR=BRG, num_warps=4)
    a = torch.mm(o_in, st["o"].t())                                    # [T, 8192] bf16
    stream1 = torch.empty((T, HIDDEN), dtype=torch.float32, device=dev)
    h = torch.empty((T, HIDDEN), dtype=torch.bfloat16, device=dev)
    _boundary_kernel[(T,)](a, data["stream"], stream1, h, a, st["a1"], st["b1"], st["pre_ffn"],
                           HAS_POST_W=False, H=HIDDEN, num_warps=4)
    # --- router and routing ---
    logits = torch.mm(h, st["router_cat"].t(), out_dtype=torch.float32)  # [T, 512]
    ids = torch.empty((T, TOP_K), dtype=torch.int32, device=dev)
    topk_w = torch.empty((T, TOP_K), dtype=torch.float32, device=dev)
    slot_e = torch.empty((T, TOP_K), dtype=torch.int32, device=dev)
    slot_pos = torch.empty((T, TOP_K), dtype=torch.int32, device=dev)
    counts = torch.zeros(LOCAL_EXPERTS, dtype=torch.int32, device=dev)
    _routing_kernel[(T,)](logits, st["router_bias"], data["local_start"], ids, topk_w, slot_e, slot_pos, counts,
                          num_warps=2)
    # --- experts ---
    pooled = torch.mm(h, st["pooler"].t())                              # [T, 4096] bf16
    moe = _experts_humming(pooled, topk_w, slot_e, st)
    if T <= 8:
        f = torch.nn.functional.pad(torch.mm(moe, st["unpooler"][:UNPOOL_SLICE].t()), (0, HIDDEN - UNPOOL_SLICE))
    else:
        f = torch.mm(moe, st["unpooler"].t())                           # [T, 8192] bf16
    stream2 = torch.empty((T, HIDDEN), dtype=torch.float32, device=dev)
    out = torch.empty((T, HIDDEN), dtype=torch.bfloat16, device=dev)
    _boundary_kernel[(T,)](f, stream1, stream2, out, st["post_ffn"], st["a2"], st["b2"], st["next_pre_attn"],
                           HAS_POST_W=True, H=HIDDEN, num_warps=4)
    return out, stream2, ids


import json
import os
from typing import TypedDict

import torch

# Importing humming starts two background `python -c` builds of helpers that the image already
# ships prebuilt. This flag, read at import, turns them off. It is restored afterwards because
# Humming also reads it to decide whether to compile kernels on parallel threads.
_saved_flag = os.environ.get("HUMMING_DISABLE_PARALLEL_BUILD")
os.environ["HUMMING_DISABLE_PARALLEL_BUILD"] = "1"
try:
    from humming import ops as humming_ops
    from humming.config import GemmType, WeightScale2Type
    from humming.kernel.humming import HummingKernel
    from humming.layer import HummingMethod
    from humming.schema.modelopt import ModeloptNvfp4WeightSchema
    from humming.tune import get_heuristics_config
finally:
    if _saved_flag is None:
        os.environ.pop("HUMMING_DISABLE_PARALLEL_BUILD", None)
    else:
        os.environ["HUMMING_DISABLE_PARALLEL_BUILD"] = _saved_flag

from sglang.kernels.ops.activation.activation import silu_and_mul
from sglang.kernels.ops.muse_spark_v12.fused_post_expert_norm_weighted_sum_triton import (
    fused_post_expert_norm_weighted_sum,
)
from sglang.srt.layers.moe.fused_moe_triton import moe_align_block_size




PRECOMPILED_MAX_BS = 32768
COMPUTE_CONFIG = json.dumps({"use_f16_accum": False, "gemm_type": GemmType.INDEXED.value})

class _Experts:
    """One GPU's experts [start, start + count) in Humming's layout, and the kernels for each bs."""

    def __init__(self, weights, start: int, count: int):
        device = weights["w13"].device
        self.count = count
        self.d_expert = weights["w13"].shape[1] // 2
        self.d_hidden = weights["w2"].shape[1]
        self.layer = torch.nn.Module()
        sl = slice(start, start + count)
        # (sublayer, N, K, N of each stacked part): w13 stacks gate and up along N.
        for name, n, k, n_stacks in (("w13", 2 * self.d_expert, self.d_hidden, [self.d_expert] * 2),
                                     ("w2", self.d_hidden, self.d_expert, [self.d_hidden])):
            checkpoint = {"weight": weights[name][sl].contiguous(),
                          "weight_scale": weights[f"{name}_sf"][sl].contiguous(),
                          "weight_scale_2": weights[f"{name}_gs"][sl].contiguous()}
            schema, tensors = ModeloptNvfp4WeightSchema().convert_humming(
                tensors=checkpoint, shape_n_stacks=n_stacks, shape_k_stacks=[k],
                param_dtype=torch.bfloat16, num_experts=count)
            # One FP32 scale per expert stays FP32. Otherwise Humming would fold it into the
            # E4M3 scales as BF16, which is lossy.
            assert schema.weight_scale_2_type == WeightScale2Type.TENSOR, schema
            for key, tensor in tensors.items():
                setattr(self.layer, f"{name}_{key}", torch.nn.Parameter(tensor, requires_grad=False))
            HummingMethod.prepare_layer_meta(
                layer=self.layer, shape_n=n, shape_k=k, weight_schema=schema, num_experts=count,
                pad_n_to_multiple=256, pad_k_to_multiple=128, torch_dtype=torch.bfloat16,
                sublayer_name=name)
            HummingMethod.transform_humming_layer(self.layer, sublayer_name=name)
        # Stream-K's semaphores, shared by the two GEMMs, which run one after the other.
        self.locks = torch.zeros(1024, dtype=torch.int32, device=device)
        self.expert_map = torch.full((N_EXPERTS,), -1, dtype=torch.int32, device=device)
        self.expert_map[sl] = torch.arange(count, dtype=torch.int32, device=device)
        self.kernels = {"w13": {}, "w2": {}}  # tuning config (JSON) -> launch configs, CPU int64
        self.plans = {}  # bs -> (routes, {sublayer: (block_m, launch configs)})
        self.compile([1 << i for i in range(16)])

    def weight(self, name: str) -> dict:
        return {"weight": getattr(self.layer, f"{name}_weight"),
                "weight_scale": getattr(self.layer, f"{name}_weight_scale"),
                "weight_scale_2": getattr(self.layer, f"{name}_weight_scale_2")}

    def routes(self, bs: int) -> int:
        """The GEMM's M for Humming's heuristics: the routes expected on this GPU."""
        return max(1, bs * TOP_K * self.count // N_EXPERTS)

    def tuning(self, name: str, routes: int) -> str:
        config = get_heuristics_config(self.layer.humming_metas[name], shape_m=routes,
                                       gemm_type=GemmType.INDEXED)
        if torch.cuda.get_device_capability()[0] == 9:
            # Exact configuration checked by the MoE owner in cand_humming3.py.
            # Indexed activation gather/scatter stays direct; weights/scales use TMA.
            config.update(use_tma=True, use_tma_a=False, use_tma_as=False, use_tma_c=False,
                          use_mbarrier=True, use_warp_spec=True)
        return json.dumps(config)

    def compile(self, batch_sizes) -> None:
        """Compile, in parallel, every kernel these batch sizes need that isn't compiled yet."""
        wanted = {bs: {name: self.tuning(name, self.routes(bs)) for name in self.kernels} for bs in batch_sizes}
        for name, kernels in self.kernels.items():
            new = sorted({t[name] for t in wanted.values()} - kernels.keys())
            if not new:
                continue
            launch = HummingKernel.prepare_kernels(
                self.layer.humming_metas[name].to_str(), COMPUTE_CONFIG,
                [[i, i + 1, json.loads(t)] for i, t in enumerate(new)])
            # A CPU tensor of rows (min M, max M, kernel id, SMs). Keep one kernel per launch config,
            # so that the kernel and this file agree on the block size of the alignment.
            for t, (_, _, kernel_id, num_sms) in zip(new, launch.view(-1, 4).tolist()):
                kernels[t] = torch.tensor([0, 1 << 30, kernel_id, num_sms], dtype=torch.int64)
        for bs, tunings in wanted.items():
            self.plans[bs] = (self.routes(bs), {name: (json.loads(t)["block_shape"][0], self.kernels[name][t])
                                                for name, t in tunings.items()})

    def plan(self, bs: int):
        bucket = 1 << (max(bs, 1) - 1).bit_length()
        if bucket not in self.plans:
            self.compile([bucket])
        return self.routes(bs), self.plans[bucket][1]




def prepare(weights):
    st = prepare_base(weights)
    st['humming'] = _Experts(weights, 0, 32)
    for key in ('w13', 'w13_sf', 'w2', 'w2_sf'):
        st.pop(key, None)
    return st


def _experts_humming(pooled, topk_w, slot_e, st):
    T = pooled.shape[0]
    x = torch.empty_like(pooled)
    _pre_expert_norm_kernel[(T,)](pooled, st['pre_expert'], x, D=D_EXPERT, num_warps=4)
    bank = st['humming']
    routes, gemms = bank.plan(T)
    local_ids = slot_e
    gate_up = torch.empty((T*8,8192),dtype=x.dtype,device=x.device)
    act = torch.empty((T*8,4096),dtype=x.dtype,device=x.device)
    y = torch.empty_like(act)
    aligned = {}
    for name, inputs, outputs, top_k in (('w13',x,gate_up,8),('w2',act,y,1)):
        block_m, launch = gemms[name]
        if block_m not in aligned:
            aligned[block_m] = moe_align_block_size(local_ids,block_m,bank.count,ignore_invalid_expert=True)
        sorted_ids,block_experts,n_padded = aligned[block_m]
        humming_ops.launch_kernel(configs=launch,inputs=inputs,outputs=outputs,**bank.weight(name),
                locks=bank.locks,sorted_ids=sorted_ids,expert_ids=block_experts,
                num_tokens_padded=n_padded,top_k=top_k,valid_shape_m=routes)
        if name == 'w13':
            silu_and_mul(gate_up,act,expert_ids=local_ids.view(-1),expert_step=1)
    return fused_post_expert_norm_weighted_sum(y.view(T,8,4096),topk_w,
            norm_weight=st['post_expert_bf16'],eps=POST_EPS,weight_first=True,slot_expert_ids=local_ids)
