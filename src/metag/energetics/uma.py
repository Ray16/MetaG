"""UMA calculation and batched FIRE with explicit numerical/runtime profiles.

Official Nitro is preferred for supported single-system optimization. Batches,
final energies, endpoint verification and Hessians use official general FP32.

API:
  pu = load_uma()
  relaxed, energies_eV = batched_fire(pu, atoms_list, fmax=0.03, steps=300)
      atoms_list: list[ase.Atoms], each with .info={"charge":int,"spin":int}

FIRE mirrors ASE's unit-mass dynamics (dt=0.1, dtmax=1.0, Nmin=5, finc=1.1,
fdec=0.5, astart=0.1, fa=0.99); per-structure dt/alpha/state, converged structures
freeze. All state on GPU; graphs rebuilt each step from current positions.
"""
import numpy as np
import torch
from ase import Atoms
from fairchem.core.datasets.atomic_data import AtomicData, atomicdata_list_to_batch

DEV = "cuda"


RUNTIME_PROFILES = ("nitro", "official_fp32")
DEFAULT_RUNTIME_PROFILE = "nitro"


def runtime_profile(value=None):
    """Resolve the calculator profile (UMA_RUNTIME_PROFILE) before model construction.

    nitro: official UMA Nitro for supported single-system optimisation, official FP32 for batches, final
    energies, convergence verification and Hessians. official_fp32: FP32 everywhere (e.g. V100)."""
    import os
    value = os.environ.get("UMA_RUNTIME_PROFILE", DEFAULT_RUNTIME_PROFILE) if value is None else value
    if not isinstance(value, str) or value.strip().lower() not in RUNTIME_PROFILES:
        raise ValueError("UMA_RUNTIME_PROFILE must be one of " + ", ".join(RUNTIME_PROFILES))
    return value.strip().lower()


def load_uma(model="uma-s-1p2p1", *, profile=None):
    """Load a UMA checkpoint as an official FairChem calculator with recorded provenance."""
    from metag.energetics.official_uma import OfficialUMACalculator
    return OfficialUMACalculator(model, profile=runtime_profile(profile), device=DEV)


def _forward(pu, atoms_list, predict):
    """Build exact input geometry/charge/spin, then preserve reference precision."""
    from metag.timing import timed
    with timed("uma.build"):           # item-A: from_ase rebuild + batch assembly + H2D copy
        datas = []
        for a in atoms_list:
            d = AtomicData.from_ase(a, task_name="omol", r_edges=False,
                                    r_data_keys=["spin", "charge"],   # <-- carry per-structure charge/spin
                                    r_energy=False, r_forces=False, r_stress=False)
            for k in ("energy", "forces", "stress"):
                if k in d:
                    del d[k]
            datas.append(d)
        batch = atomicdata_list_to_batch(datas).to(DEV)
    with timed("uma.gpu", sync=True):  # real GPU forward (CUDA-synced under profiling)
        pred = predict(batch)
    # Preserve float64 totals through unit conversion and energy differences.
    # The inspected OMol checkpoint restores elemental references in float64;
    # its learned residuals/forces can still be float32. Do not downcast totals
    # or infer their precision from the neural-network parameter dtype alone.
    E = pred["energy"].detach().double().view(-1)         # (N,)
    F = pred["forces"].detach().float()                    # (total,3)
    if E.numel() != len(atoms_list) or tuple(F.shape) != (sum(map(len, atoms_list)), 3):
        raise RuntimeError("UMA returned energy/force arrays inconsistent with the requested structures")
    if not bool(torch.isfinite(E).all()) or not bool(torch.isfinite(F).all()):
        raise RuntimeError("UMA returned nonfinite energies or forces")
    return E, F, batch.batch.to(F.device).long()


def _predict(pu, atoms_list):
    """Final/ranking energy and force evaluation; official profiles use FP32."""
    predict = pu.predict_precise if getattr(pu, "_metag_official_calculator", False) is True else pu.predict
    return _forward(pu, atoms_list, predict)


def _predict_relaxation(pu, atoms_list):
    return _forward(pu, atoms_list, pu.predict)


import os as _os
_ENERGY_CHUNK = int(_os.environ.get("UMA_ENERGY_CHUNK", "256"))


_FIRE_CHUNK = int(_os.environ.get("UMA_FIRE_CHUNK", "0"))   # 0 = one batch (default); >0 = chunk force eval


def _predict_chunked(pu, atoms_list, chunk):
    """Same return as _predict, but evaluate forces in chunks of `chunk` structures
    and stitch back into a single (E, F, batch_idx) — result-preserving memory lever
    (forces are independent per structure). chunk<=0 -> single batch (identity)."""
    predict = (_predict_relaxation if getattr(pu, "_metag_official_calculator", False) is True
               else _predict)
    return _chunked_forward(pu, atoms_list, chunk, predict)


def _predict_precise_chunked(pu, atoms_list, chunk):
    return _chunked_forward(pu, atoms_list, chunk, _predict)


def _chunked_forward(pu, atoms_list, chunk, predict):
    if chunk is None or chunk <= 0 or len(atoms_list) <= chunk:
        return predict(pu, atoms_list)
    Es, Fs, bis, offset = [], [], [], 0
    for i in range(0, len(atoms_list), chunk):
        sub = atoms_list[i:i + chunk]
        E, F, bi = predict(pu, sub)
        Es.append(E); Fs.append(F); bis.append(bi + offset)
        offset += len(sub)
    return torch.cat(Es), torch.cat(Fs), torch.cat(bis)


def batched_energies(pu, atoms_list, chunk=None):
    """Batched single-point energies (eV) for ranking; no relaxation. Chunked to
    bound GPU memory when the pool is large. `chunk` defaults to UMA_ENERGY_CHUNK
    (result-preserving memory lever for big molecules on small GPUs)."""
    if chunk is None:
        chunk = _ENERGY_CHUNK
    out = []
    for i in range(0, len(atoms_list), chunk):
        E, _, _ = _predict(pu, atoms_list[i:i + chunk])
        out.append(E.cpu().numpy())
    return np.concatenate(out) if out else np.array([])


def batched_fire(pu, atoms_list, fmax=0.05, steps=300, maxstep=0.2, stop_frac=1.0,
                 straggler_fmax=None, return_converged=False, dt0=0.1, dtmax=1.0,
                 Nmin=5, finc=1.1, fdec=0.5, astart=0.1, fa=0.99,
                 verbose=False, log_every=25, label="", fix_mask=None, extra_forces=None,
                 _reference_only=False):
    """Relax all atoms_list simultaneously. Returns (relaxed_atoms, energies_eV np).
    Straggler-robust: stops early once `stop_frac` of structures are below `fmax`
    AND every remaining structure is below `straggler_fmax` (default 2*fmax) — so a
    single slow conformer can't drag the whole batch to the step cap (energies of
    near-converged stragglers are fine to <~1 kJ). verbose prints per-step progress.

    fix_mask: optional per-atom bool over the FLAT concatenated atom list (length =
    Σ len(atoms_list)), True = FROZEN. Frozen atoms have their force zeroed, so they
    never move and convergence is judged on the FREE atoms only. Used by matched /
    frozen-scaffold relaxation: the conserved spectator is pinned at a shared geometry
    (identical across the reactant/product pair) so it cancels exactly in ΔE, and only
    the transformation region relaxes.

    extra_forces: optional callable(atoms_list, done_bool_array) -> (total,3) eV/Å added to the UMA forces
    every step (e.g. the continuum-solvation gradient, metag.energetics.solv_relax). Structures already
    below fmax are passed as done; reuse their unchanged solvent forces rather than returning zeros.
    Returned energies and convergence refer to the returned coordinates,
    including one final evaluation if the optimization-step budget is exhausted."""
    if steps < 0:
        raise ValueError("FIRE steps must be nonnegative")
    straggler_fmax = straggler_fmax if straggler_fmax is not None else 2.0 * fmax
    import time as _time
    _t0 = _time.time()
    N = len(atoms_list)
    nat = torch.tensor([len(a) for a in atoms_list], device=DEV)
    # flat positions (total,3); per-atom structure index
    pos = torch.tensor(np.concatenate([a.get_positions() for a in atoms_list]),
                       dtype=torch.float32, device=DEV)
    # frozen-atom free-mask (1.0 = free, 0.0 = frozen); multiplies forces so frozen
    # atoms feel zero force -> zero velocity -> never move, and don't gate convergence.
    freemask = None
    if fix_mask is not None:
        fm = torch.as_tensor(np.asarray(fix_mask, dtype=bool), device=DEV)
        assert fm.shape[0] == pos.shape[0], "fix_mask length must equal total atom count"
        freemask = (~fm).float().unsqueeze(1)                # (total,1)
    bidx = torch.repeat_interleave(torch.arange(N, device=DEV), nat)
    v = torch.zeros_like(pos)
    dt = torch.full((N,), dt0, device=DEV)
    alpha = torch.full((N,), astart, device=DEV)
    Npos = torch.zeros(N, dtype=torch.long, device=DEV)
    done = torch.zeros(N, dtype=torch.bool, device=DEV)
    E_last = torch.zeros(N, device=DEV)

    def scat(x):  # per-structure sum of per-atom scalar x
        return torch.zeros(N, device=DEV).scatter_add_(0, bidx, x)

    official = getattr(pu, "_metag_official_calculator", False) is True
    nitro_before = (pu.execution_snapshot()["counts"].get("actual_nitro_calls", 0)
                    if official else 0)
    forward = _predict_precise_chunked if official and _reference_only else _predict_chunked
    exhausted = True
    moves_used = 0
    for _step in range(steps):
        # write current positions back into the Atoms, predict forces (batched)
        from metag.timing import timed
        with timed("uma.writeback"):   # item-A: positions GPU->CPU->ASE set_positions, every step
            off = 0
            for i, a in enumerate(atoms_list):
                n = int(nat[i]); a.set_positions(pos[off:off + n].detach().cpu().numpy()); off += n
        E, F, bi = forward(pu, atoms_list, _FIRE_CHUNK)
        E_last = E
        if extra_forces is not None:
            Fx = extra_forces(atoms_list, done.detach().cpu().numpy())
            F = F + torch.as_tensor(np.asarray(Fx), dtype=F.dtype, device=F.device)
        if freemask is not None:
            F = F * freemask                                 # frozen atoms: zero force -> never move / never gate convergence
        # per-structure max force
        fnorm = F.norm(dim=1)
        fmax_s = torch.zeros(N, device=DEV).scatter_reduce_(0, bi, fnorm, reduce="amax",
                                                            include_self=False)
        done = fmax_s < fmax
        frac = float(done.float().mean())
        worst = float(fmax_s.max())
        early = (frac >= stop_frac) and (worst < straggler_fmax)
        if verbose and (_step % log_every == 0 or bool(done.all()) or early):
            print(f"    [relax{(' '+label) if label else ''}] step {_step:4d}  "
                  f"converged {int(done.sum()):3d}/{N}  worst fmax {worst:.3f}  "
                  f"{_time.time()-_t0:5.1f}s", flush=True)
        if bool(done.all()) or early:
            exhausted = False
            break
        active_atom = ~done[bi]                              # mask atoms of unconverged structures
        # FIRE mixing (per structure)
        P = scat((F * v).sum(1))                             # power
        vn = scat((v * v).sum(1)).sqrt()
        fn = scat((F * F).sum(1)).sqrt().clamp(min=1e-12)
        pos_pow = (P > 0) & ~done
        # v = (1-a) v + a |v|/|f| * F   for structures with P>0
        mix = alpha[bi].unsqueeze(1)
        scale = (vn / fn)[bi].unsqueeze(1)
        v_mixed = (1 - mix) * v + mix * scale * F
        v = torch.where(pos_pow[bi].unsqueeze(1), v_mixed, v)
        # adapt dt/alpha for P>0
        Npos = torch.where(pos_pow, Npos + 1, torch.zeros_like(Npos))
        grow = pos_pow & (Npos > Nmin)
        dt = torch.where(grow, (dt * finc).clamp(max=dtmax), dt)
        alpha = torch.where(grow, alpha * fa, alpha)
        # reset for P<=0
        neg = (P <= 0) & ~done
        v = torch.where(neg[bi].unsqueeze(1), torch.zeros_like(v), v)
        dt = torch.where(neg, dt * fdec, dt)
        alpha = torch.where(neg, torch.full_like(alpha, astart), alpha)
        # MD step (unit mass): v += dt F ; dr = dt v, capped at maxstep per atom
        step_dt = torch.where(done, torch.zeros_like(dt), dt)[bi].unsqueeze(1)
        v = v + step_dt * F
        dr = step_dt * v
        drn = dr.norm(dim=1, keepdim=True).clamp(min=1e-12)
        dr = torch.where(drn > maxstep, dr * (maxstep / drn), dr)   # ASE FIRE maxstep cap
        pos = pos + dr
        moves_used += 1

    # write final positions
    off = 0
    for i, a in enumerate(atoms_list):
        n = int(nat[i]); a.set_positions(pos[off:off + n].detach().cpu().numpy()); off += n
    used_nitro = (official and pu.execution_snapshot()["counts"].get("actual_nitro_calls", 0) > nitro_before)
    if exhausted or (used_nitro and not _reference_only):
        # The last allowed move changes positions after the last forward pass.
        # Report the endpoint's energy and forces, not the preceding geometry's.
        endpoint = _predict_precise_chunked if official else _predict_chunked
        E_last, F, bi = endpoint(pu, atoms_list, _FIRE_CHUNK)
        if extra_forces is not None:
            Fx = extra_forces(atoms_list, np.zeros(N, dtype=bool))
            F = F + torch.as_tensor(np.asarray(Fx), dtype=F.dtype, device=F.device)
        if freemask is not None:
            F = F * freemask
        fmax_s = torch.zeros(N, device=DEV).scatter_reduce_(
            0, bi, F.norm(dim=1), reduce="amax", include_self=False)
        done = fmax_s < fmax
    if used_nitro and not _reference_only and not bool(done.all()) and moves_used < steps:
        # Approximate optimization cannot certify a minimum. Spend only the
        # original remaining budget on the official FP32 potential.
        pu.record("fp32_endpoint_refinements")
        return batched_fire(
            pu, atoms_list, fmax=fmax, steps=steps-moves_used, maxstep=maxstep,
            stop_frac=stop_frac, straggler_fmax=straggler_fmax,
            return_converged=return_converged, dt0=dt0, dtmax=dtmax, Nmin=Nmin,
            finc=finc, fdec=fdec, astart=astart, fa=fa, verbose=verbose,
            log_every=log_every, label=label, fix_mask=fix_mask,
            extra_forces=extra_forces, _reference_only=True)
    converged = done.detach().cpu().numpy()   # per-structure: reached fmax
    if return_converged:
        return atoms_list, E_last.detach().cpu().numpy(), converged
    return atoms_list, E_last.detach().cpu().numpy()
