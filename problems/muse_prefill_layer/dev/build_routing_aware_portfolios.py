"""Build immutable prefill portfolios whose expert tuner uses the layer's router distribution."""
from pathlib import Path
import ast
import argparse
import hashlib
import textwrap

P = Path(__file__).resolve().parents[1]

ROUTING_TUNER = r'''

def _expert_realistic(T, st):
    """Build a prepare-only expert fixture from this layer's own router weights.

    The random hidden rows are BF16 and normalized like the layer's post-residual h.  The
    router is the lossless BF16 hi+lo bank prepared from weights["router"].  We select the
    busiest 32-expert range exactly as reference.case_fields does, then form the local
    slot map and per-expert counts consumed by every expert implementation.
    """
    dev = st['qkv'].device
    gen = st['_generator']
    # Match the layer's random stream shape (fixed mean + low-rank shared component + noise),
    # then apply the same RMS/pre-FFN transform that feeds the router.  These are still fresh
    # random hidden rows; the structured draw prevents the tuner from seeing an unrealistically
    # uniform router population.
    basis_gen = torch.Generator(device='cpu').manual_seed(5354)
    mean = torch.randn((HIDDEN,), generator=basis_gen).to(dev)
    shared = torch.randn((4, HIDDEN), generator=basis_gen).to(dev)
    coef = torch.randn((T, 4), device=dev, generator=gen)
    hidden = (0.7 * mean + (0.9 / 4.0) ** 0.5 * (coef @ shared)
              + (1.0 - 0.9) ** 0.5 * torch.randn((T, HIDDEN), device=dev, generator=gen))
    hidden = hidden * torch.rsqrt(hidden.square().mean(-1, keepdim=True) + 1e-5)
    hidden = (hidden * st['pre_ffn']).to(torch.bfloat16)
    if '_router_original' in st:
        logits = torch.mm(hidden.float(), st['_router_original'].t())
    else:
        router = st['router_cat']
        hi = torch.mm(hidden, router[:N_EXPERTS].t(), out_dtype=torch.float32)
        lo = torch.mm(hidden, router[N_EXPERTS:].t(), out_dtype=torch.float32)
        logits = hi + lo
    scores = torch.sigmoid(logits * ROUTER_MULT)
    biased = scores + st['router_bias']
    ids = torch.topk(biased, TOP_K, dim=-1, sorted=True).indices
    probs = scores.gather(1, ids)
    probs = probs / (probs.sum(-1, keepdim=True) + 1e-15)
    groups = torch.bincount((ids // LOCAL_EXPERTS).reshape(-1), minlength=N_EXPERTS // LOCAL_EXPERTS)
    local_start = int(groups.argmax().item()) * LOCAL_EXPERTS
    local = (ids - local_start) % N_EXPERTS
    is_local = local < LOCAL_EXPERTS
    slot_e = torch.where(is_local, local, torch.full_like(local, -1)).to(torch.int32)
    flat = local.reshape(-1)
    flat_pos = torch.zeros_like(flat, dtype=torch.int32)
    for expert in range(LOCAL_EXPERTS):
        m = flat == expert
        flat_pos = torch.where(m, torch.cumsum(m.to(torch.int32), 0) - 1, flat_pos)
    slot_pos = torch.where(is_local.reshape(-1), flat_pos, torch.zeros_like(flat_pos)).reshape(T, TOP_K)
    counts = torch.bincount(flat[flat < LOCAL_EXPERTS], minlength=LOCAL_EXPERTS).to(torch.int32)
    # Match the layer boundary: expert paths receive the BF16 pooler output and perform their
    # own pre-expert norm inside the timed call.  This keeps route IDs and expert activations
    # correlated without retaining any prepare-time result in the submission state.
    pooled = torch.mm(hidden, st['pooler'].t(), out_dtype=torch.float32).to(torch.bfloat16)
    return pooled, probs, slot_e, slot_pos, counts


def _tune_score_experts(st, flush):
    """Compare the legacy uniform fixture and router-realistic fixture, select realistic."""
    for T in (753, 3012, 16384):
        if _time_left(st) < 12:
            print('SCORE_TUNING_BUDGET realistic expert shapes omitted', flush=True)
            return
        control = 'raw11' if T < 8192 else 'raw_v11'
        synthetic_selected = control
        synthetic_record = {}
        try:
            synthetic = _expert_synthetic(T, st, 2)
            def run_synthetic(name):
                return _score_expert(*synthetic, st, name)
            def refresh_synthetic(_):
                synthetic[0].normal_(generator=st['_generator'])
            cache = [-1, None]
            def verify_synthetic(out):
                if cache[0] != synthetic[0]._version:
                    sample = tuple(v[:64] if i < 4 else v for i, v in enumerate(synthetic))
                    cache[:] = [synthetic[0]._version, _score_expert_oracle(sample, st)]
                return _judge_floor(out[:64], cache[1], f'expert synthetic {T}')
            synthetic_selected, synthetic_record = _score_select(
                _EXPERT_CHOICES, control, run_synthetic, verify_synthetic,
                refresh_synthetic, flush, st, f'expert synthetic {T}')
            del synthetic, cache
        except Exception as error:
            _score_reject(f'expert synthetic shape {T}', error)

        realistic_selected = control
        realistic_record = {}
        # Keep the compact prepare log valid even if every realistic candidate is rejected.
        if not synthetic_record:
            synthetic_record = dict(choices=[], us=[], selected=synthetic_selected, errors={})
        try:
            realistic = _expert_realistic(T, st)
            route_counts = realistic[-1]
            route_distinct = int((route_counts > 0).sum().item())
            route_total = int(route_counts.sum().item())
            def run_realistic(name):
                return _score_expert(*realistic, st, name)
            def refresh_realistic(_):
                realistic[0].normal_(generator=st['_generator'])
            cache = [-1, None]
            def verify_realistic(out):
                if cache[0] != realistic[0]._version:
                    sample = tuple(v[:64] if i < 4 else v for i, v in enumerate(realistic))
                    cache[:] = [realistic[0]._version, _score_expert_oracle(sample, st)]
                return _judge_floor(out[:64], cache[1], f'expert realistic {T}')
            realistic_selected, realistic_record = _score_select(
                _EXPERT_CHOICES, control, run_realistic, verify_realistic,
                refresh_realistic, flush, st, f'expert realistic {T}')
            realistic_record['synthetic_selected'] = str(synthetic_selected)
            realistic_record['synthetic_us'] = synthetic_record.get('us', [])
            realistic_record['synthetic_choices'] = synthetic_record.get('choices', [])
            realistic_record['route_total'] = route_total
            realistic_record['route_distinct'] = route_distinct
            st['expert_dispatch'][T] = realistic_selected
            st['_measurements']['expert'][T] = realistic_record
            print('SCORE_ROUTING', json.dumps(dict(
                tokens=T, synthetic_selected=synthetic_selected,
                realistic_selected=realistic_selected,
                synthetic_us=synthetic_record.get('us', []),
                realistic_us=realistic_record.get('us', []),
                route_total=route_total, route_distinct=route_distinct)), flush=True)
            del realistic, cache
        except Exception as error:
            _score_reject(f'expert realistic shape {T}', error)
            st['expert_dispatch'][T] = synthetic_selected
            st['_measurements']['expert'][T] = synthetic_record
'''


def guarded(source: str) -> str:
    # Every queued base has the common rejection contract; rebuild it for the older score source.
    from builder_safety import guarded_tuners
    return guarded_tuners(source)


def build(source: Path, output: Path) -> None:
    source_text = guarded(source.read_text())
    # Appending overrides is deliberate: prepare resolves the final definition after module load,
    # while the queued source remains byte-for-byte untouched.
    result = source_text.rstrip() + '\n' + textwrap.dedent(ROUTING_TUNER).lstrip()
    ast.parse(result)
    output.write_text(result)
    print(f'{output} bytes={output.stat().st_size} sha256={hashlib.sha256(result.encode()).hexdigest()} parent={hashlib.sha256(source.read_bytes()).hexdigest()}')


if __name__ == '__main__':
    parser = argparse.ArgumentParser()
    parser.add_argument('--output-dir', type=Path, default=P)
    args = parser.parse_args()
    build(P / 'cand_score_portfolio.py', args.output_dir / 'cand_score_portfolio_routing.py')
    build(P / 'cand_fused_expert_portfolio.py', args.output_dir / 'cand_fused_expert_portfolio_routing.py')
    build(P / 'cand_dense_fusion_portfolio.py', args.output_dir / 'cand_dense_fusion_portfolio_routing.py')
