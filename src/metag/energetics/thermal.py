#!/usr/bin/env python
"""Conformer thermochemistry and vertical implicit-solvent corrections.

UMA force-autograd Hessians are the default; central finite differences remain
available for historical reproduction. External modes are projected before the
stated imaginary-mode and low-frequency policies are applied. RRHO is a gas
thermochemistry approximation, not a validated aqueous entropy model.

Solvation uses matched GFN2/ALPB(water) single points at one geometry, with
explicit charge and spin. Numerical return codes and finite results govern
admission; the calling ensemble layer decides whether an unavailable state
permits an estimate. Supplied-Hessian thermochemistry and external solvation import without UMA;
model-specific Hessian helpers load their optional backend only when called.
"""
import os
import re
import subprocess
import tempfile

import numpy as np
from ase import Atoms
from ase.thermochemistry import IdealGasThermo

def _predict(pu, atoms_list):
    """Load the optional UMA backend only when molecular forces are requested.

    RRHO from a supplied Hessian and xTB solvation remain CPU utilities with
    NumPy/ASE; they must not import Torch or fairchem merely to read a Hessian.
    """
    from metag.energetics.uma import _predict as predict
    return predict(pu, atoms_list)

EV2KJ = 96.485
CM2EV = 1.23984e-4
HARTREE2KJ = 2625.499639
T = 298.15
XTB = os.environ.get("XTB_BIN") or "xtb"     # absolute path recommended; resolved on PATH otherwise
ENV = {**os.environ, "OMP_NUM_THREADS": "1", "MKL_NUM_THREADS": "1",
       "OPENBLAS_NUM_THREADS": "1", "OMP_STACKSIZE": "4G"}


# ------------------------------------------------------------------ thermal (UMA)
_HESS_CHUNK = int(os.environ.get("UMA_HESS_CHUNK", "128"))


def _forces_batched(pu, structs, chunk=None):
    """Per-structure forces (list of (nat,3) arrays) via batched UMA passes.
    chunk defaults to UMA_HESS_CHUNK (result-preserving memory lever for big
    molecules on small GPUs; forces are independent per displaced structure)."""
    if chunk is None:
        chunk = _HESS_CHUNK
    out = [None] * len(structs)
    for s in range(0, len(structs), chunk):
        sub = structs[s:s + chunk]
        _, F, bi = _predict(pu, sub)
        F = F.detach().cpu().numpy(); bi = bi.detach().cpu().numpy()
        for k in range(len(sub)):
            out[s + k] = F[bi == k]
    return out


# ------------------------------------------------------------------ exact (autograd) Hessian
# UMA_HESSIAN selects how the Cartesian Hessian is obtained:
#   autograd (DEFAULT since 2026-10-06) the EXACT second derivative of the UMA energy (UMA is conservative, F = -dE/dx): one forward
#            pass with a differentiable force graph, then 3N vector-Jacobian products, UMA_HESS_ROWS rows
#            per batched double-backward (memory lever for big molecules; result-preserving).
#            Validated vs fd on 10 species: FD error scales as delta^2 toward it (it is FD's converged limit);
#            Gcorr within 0.18 kJ/mol (qRRHO off); 2-6x faster and ~half the peak GPU memory on big species.
#   fd       legacy central finite differences of UMA forces, 6N displaced structures, batched. Reproduces
#            caches/results made before 2026-10-06 (its cache keys omit the 'hessian' field).
# The projection, frequency floor, qRRHO and symmetry handling downstream are identical for both.
_HESS_ROWS = int(os.environ.get("UMA_HESS_ROWS", "0"))      # 0 = auto (by atom count)


def hessian_method():
    """UMA_HESSIAN env flag: 'autograd' (default) or 'fd' (legacy). Part of the species-cache key when not 'fd'."""
    v = os.environ.get("UMA_HESSIAN", "autograd").strip().lower()
    if v in ("fd", "finite", "finite-difference"):
        return "fd"
    if v in ("", "autograd", "ad", "exact"):
        return "autograd"
    raise ValueError(f"UMA_HESSIAN={v!r}: expected 'fd' or 'autograd'")


_HESS_MEMO_N = int(os.environ.get("HESS_MEMO_N", "16"))     # per-model LRU of (E_elec, H); 0 = off


def _hess_memo(pu):
    """The predict unit's Hessian memo (an LRU dict), or None if disabled / pu can't carry attributes."""
    if _HESS_MEMO_N <= 0:
        return None
    memo = getattr(pu, "_metag_hess_memo", None)
    if memo is None:
        from collections import OrderedDict
        try:
            pu._metag_hess_memo = memo = OrderedDict()
        except AttributeError:                                 # e.g. pu=None in mocked tests
            return None
    return memo


def _auto_rows(nat):
    """VJP rows per batched double-backward. Wall time is nearly flat in rows (measured 8 vs 24 rows: <10%),
    peak memory is ~linear in rows x graph size (measured: 85-atom CoA-like 5.0 GB @8 rows, 12.3 GB @24;
    70-atom NAD 3.8 / 9.4 GB), so small chunks cost nothing and keep big species far below the ~14.6 GB
    effective card. An OOM still halves the chunk and retries (_hessian_from_forces)."""
    if _HESS_ROWS > 0:
        return _HESS_ROWS
    return min(3 * nat, 16) if nat <= 40 else (8 if nat <= 120 else 4)


class _ForceGraph:
    """Context manager: make the UMA head build its forces with create_graph=True (needed for a second
    derivative) and capture the position leaf they are differentiated against. fairchem's MLP_EFS_Head
    calls compute_forces(..., training=self.training) or, when the checkpoint regresses stress (uma-s-1p2
    does), compute_forces_and_stress(..., training=self.training or regress_config.hessian) -- False at
    inference, i.e. no graph. We rebind both module-level names for the duration of one predict call only
    (not thread-safe; the pipeline drives the GPU from one thread)."""

    def __enter__(self):
        import fairchem.core.models.uma.escn_md as m
        self._m, self.pos = m, None
        self._orig = (m.compute_forces, m.compute_forces_and_stress)
        of, ofs = self._orig

        def cf(energy_part, pos, training=False):
            self.pos = pos
            return of(energy_part, pos, training=True)

        def cfs(energy_part, pos, cell, batch, training=False):
            self.pos = pos
            return ofs(energy_part, pos, cell, batch=batch, training=True)
        m.compute_forces, m.compute_forces_and_stress = cf, cfs
        return self

    def __exit__(self, *exc):
        self._m.compute_forces, self._m.compute_forces_and_stress = self._orig
        return False


def _hessian_from_forces(F_flat, pos, rows):
    """H = -dF/dx (3N x 3N, float64 numpy) by batched VJPs against identity rows. F_flat: (3N,) with graph.
    A CUDA OOM halves the row chunk and retries (result-preserving: rows are independent); if the batched
    (vmap) backward is unsupported for some op, falls back to one VJP per row."""
    import torch
    n = F_flat.numel()
    H = np.empty((n, n))
    eye = torch.eye(n, device=F_flat.device, dtype=F_flat.dtype)
    batched, s = True, 0
    while s < n:
        e = min(n, s + rows)
        if batched:
            try:
                g, = torch.autograd.grad(F_flat, pos, grad_outputs=eye[s:e], is_grads_batched=True,
                                         retain_graph=True)
                H[s:e] = -g.reshape(e - s, n).double().cpu().numpy()
                s = e
                continue
            except torch.cuda.OutOfMemoryError:
                if rows == 1:
                    raise
                torch.cuda.empty_cache(); rows = max(1, rows // 2)
                continue
            except RuntimeError:
                batched = False
        for r in range(s, e):
            g, = torch.autograd.grad(F_flat, pos, grad_outputs=eye[r], retain_graph=True)
            H[r] = -g.reshape(n).double().cpu().numpy()
        s = e
    return H


def uma_hessian_autograd(pu, atoms, rows=None):
    """Exact UMA Cartesian Hessian (eV/Å², 3N x 3N numpy, symmetrised) of ONE structure. atoms.info must
    carry int charge/spin (they are passed through r_data_keys, else the structure is computed neutral)."""
    import torch
    from fairchem.core.datasets.atomic_data import AtomicData, atomicdata_list_to_batch
    from metag.energetics.uma import DEV
    nat = len(atoms)
    if nat == 1:
        return np.zeros((3, 3))
    if getattr(pu, "_metag_official_calculator", False) is True:
        pu.record("autograd_hessian_calls")
    d = AtomicData.from_ase(atoms, task_name="omol", r_edges=False, r_data_keys=["spin", "charge"],
                            r_energy=False, r_forces=False, r_stress=False)
    for k in ("energy", "forces", "stress"):
        if k in d:
            del d[k]
    batch = atomicdata_list_to_batch([d]).to(DEV)
    from contextlib import nullcontext
    precision = (pu.precision_context() if getattr(pu, "_metag_official_calculator", False) is True
                 else nullcontext())
    with torch.enable_grad(), precision:
        with _ForceGraph() as fg:
            # Nitro cannot supply the differentiable FP32 force graph used by
            # this Hessian. Keep the official model semantics and precision.
            predict = pu.predict_precise if getattr(pu, "_metag_official_calculator", False) is True else pu.predict
            pred = predict(batch)
        F = pred["forces"]
        if fg.pos is None or not F.requires_grad:
            raise RuntimeError("UMA forces carry no autograd graph (direct-force model?) -- use UMA_HESSIAN=fd")
        H = _hessian_from_forces(F.reshape(-1), fg.pos, rows or _auto_rows(nat))
    del pred, F, fg, batch
    return 0.5 * (H + H.T)


def fd_hessian(pu, base, delta=0.01, chunk=None):
    """Central-difference Hessian (eV/Å², symmetrised) from UMA forces at +/- delta on every Cartesian DOF;
    the 6N displaced structures go through batched UMA passes (chunk = UMA_HESS_CHUNK)."""
    symbols = base.get_chemical_symbols(); pos0 = base.get_positions()
    q, spin = int(base.info["charge"]), int(base.info["spin"])
    nat = len(base); ndof = 3 * nat
    structs = []
    for i in range(nat):
        for c in range(3):
            for sgn in (+1.0, -1.0):
                p = pos0.copy(); p[i, c] += sgn * delta
                structs.append(Atoms(symbols=symbols, positions=p, info={"charge": q, "spin": spin}))
    from metag.timing import timed
    with timed("hessian"):                                 # 6N displaced-forces phase (forwards also in uma.gpu)
        F = _forces_batched(pu, structs, chunk=chunk)      # eV/Å, list of (nat,3)
    H = np.zeros((ndof, ndof))
    for d in range(ndof):
        Fp = F[2 * d].reshape(-1); Fm = F[2 * d + 1].reshape(-1)
        H[d] = -(Fp - Fm) / (2.0 * delta)                  # eV/Å²
    return 0.5 * (H + H.T)


# |imaginary| frequencies up to this are finite-difference / loose-optimisation noise on soft modes and are
# floored like any other soft mode; above it the structure is not a minimum (reported, caller retries).
IMAG_TOL_CM = 50.0


def internal_vib_energies(atoms, H, geometry, return_modes=False):
    """Vibrational analysis with translations and rotations PROJECTED OUT (Eckart), not dropped by size.

    H = Cartesian Hessian (eV/Å², 3N x 3N). Returns (vib_energies_eV, imag_cm): the real vibrational
    quanta of the 3N - n_ext internal modes, and the |frequencies| (cm^-1) of internal modes with negative
    curvature. The old treatment took |Re(E)| of all 3N modes and dropped the n_ext smallest, so a purely
    imaginary mode (Re = 0) became a 'rotation' or a floored 50 cm^-1 mode and a saddle point received
    ordinary minimum thermochemistry."""
    from ase import units
    m = atoms.get_masses()
    x = atoms.get_positions() - atoms.get_center_of_mass()
    n = len(m)
    sm = np.repeat(np.sqrt(m), 3)
    Hmw = H / np.outer(sm, sm)                                  # eV / (Å² amu)
    ext = []
    for a in range(3):                                          # translations
        v = np.zeros((n, 3)); v[:, a] = 1.0
        ext.append((v * np.sqrt(m)[:, None]).ravel())
    for a in range(3):                                          # rotations about the centre of mass
        e = np.zeros(3); e[a] = 1.0
        ext.append((np.cross(e, x) * np.sqrt(m)[:, None]).ravel())
    n_ext = {"monatomic": 3, "linear": 5, "nonlinear": 6}[geometry]
    U, sv, _ = np.linalg.svd(np.array(ext).T, full_matrices=True)
    B = U[:, n_ext:]                                            # orthonormal basis of the internal space
    lam, vec = np.linalg.eigh(B.T @ Hmw @ B)
    s = units._hbar * 1e10 / np.sqrt(units._e * units._amu)     # sqrt(eV/Å²/amu) -> eV (as ASE)
    e = s * np.sqrt(np.abs(lam))
    if return_modes:                                            # Cartesian displacement of each negative mode
        cart = [((B @ vec[:, k]) / sm).reshape(n, 3) for k in np.nonzero(lam < 0)[0]]
        cart = [c / np.linalg.norm(c) for c in cart]
        return e[lam >= 0], e[lam < 0] / CM2EV, cart
    return e[lam >= 0], e[lam < 0] / CM2EV


def uma_gibbs_corr(pu, symbols, coords, q, delta=0.01, chunk=None,
                   geometry=None, symmetrynumber=None, spin=1, return_info=False, imag_as_soft=False,
                   hessian=None):
    """Gibbs correction Gcorr = G_gas(RRHO,ideal-gas) - E_elec (kJ/mol), UMA Hessian.

    Hessian: hessian='autograd' (default, UMA_HESSIAN env) = the exact UMA Hessian by double backward
    (uma_hessian_autograd; `delta`/`chunk` unused); hessian='fd' (legacy) = central-difference Hessian
    from UMA forces, all 6N displacements batched (step `delta` Å). Uses the same low-frequency floor (50 cm^-1)
    as step6.

    The molecular geometry (linear vs nonlinear -> drop 5 vs 6 external modes) and the rotational
    symmetry number sigma are DETECTED from the geometry (mol_symmetry.geometry_and_sigma), not
    hard-coded: sigma=1/nonlinear-for-everything biases every reaction whose net species include a
    symmetric molecule (water sigma=2 does not cancel when water is created/destroyed) and mis-treats
    the linear species (CO2/O2/H2/N2) common in ModelSEED. Pass geometry/symmetrynumber explicitly only
    to override the automatic detection (e.g. for testing).
    """
    from metag.symmetry import geometry_and_sigma
    geo_auto, sigma_auto, n_drop = geometry_and_sigma(symbols, coords)
    if geometry is None:
        geometry = geo_auto
    if symmetrynumber is None:
        symmetrynumber = sigma_auto
    base = Atoms(symbols=symbols, positions=np.asarray(coords, float),
                 info={"charge": int(q), "spin": int(spin)})
    method = hessian or hessian_method()
    if method not in ("autograd", "fd"):
        raise ValueError(f"hessian={method!r}: expected 'fd' or 'autograd'")
    # HESSIAN MEMO (result-preserving): the pipeline evaluates the SAME geometry more than once -- the
    # thermal-ensemble track (imag_as_soft) and _thermal_at_minimum's strict validation both hit the lowest
    # minimum, and an "artefact" verdict recomputes it with imag_as_soft. Everything those calls vary acts
    # AFTER H, so (E_elec, H) is reused for an identical geometry/charge/spin/method. Stored on the predict
    # unit (scoped to that model); HESS_MEMO_N=0 disables. Not part of any cache key.
    memo = _hess_memo(pu)
    mkey = (tuple(symbols), base.get_positions().tobytes(), int(q), int(spin), method,
            float(delta) if method == "fd" else None)
    hit = memo.get(mkey) if memo is not None else None
    if hit is not None:
        memo.move_to_end(mkey)
        E_elec, H = hit
    else:
        # electronic energy at the (already UMA-relaxed) geometry
        E_eV, _, _ = _predict(pu, [base]); E_elec = float(E_eV.detach().cpu().numpy()[0])
        from metag.timing import timed
        if method == "autograd":
            with timed("hessian"):
                H = uma_hessian_autograd(pu, base)         # exact d2E/dx2, eV/Å², symmetrised
        else:
            H = fd_hessian(pu, base, delta=delta, chunk=chunk)
        if memo is not None:
            memo[mkey] = (E_elec, H)
            while len(memo) > _HESS_MEMO_N:
                memo.popitem(last=False)
    return gibbs_corr_from_hessian(base, H, E_elec, geometry, symmetrynumber, spin=spin,
                                   return_info=return_info, imag_as_soft=imag_as_soft)


def gibbs_corr_from_hessian(base, H, E_elec, geometry, symmetrynumber, spin=1, return_info=False,
                            imag_as_soft=False, *, temperature_K=None, pressure_Pa=101325.0):
    """Gcorr (kJ/mol) from a Cartesian Hessian H (eV/Å²) at geometry `base` (E_elec in eV): Eckart
    projection, imaginary-mode handling, 50 cm^-1 floor, ideal-gas RRHO. Pure CPU;
    shared by both Hessian back-ends so they differ ONLY in H.

    Explicit temperature/pressure apply only to this supplied-Hessian gas
    calculation; they do not change the reaction pipeline or its solution-state
    models. Returned thermodynamic components are conditional on the same
    projected modes, frequency floor and optional qRRHO entropy model as Gcorr.
    They support phase-matched diagnostics, not an uncertainty estimate.
    """
    temperature = T if temperature_K is None else temperature_K
    for name, value in (("temperature_K", temperature), ("pressure_Pa", pressure_Pa)):
        if isinstance(value, (bool, np.bool_)) or not np.isscalar(value):
            raise ValueError(f"{name} must be a positive finite number")
        try:
            valid = np.isfinite(value) and value > 0
        except TypeError:
            valid = False
        if not valid:
            raise ValueError(f"{name} must be a positive finite number")
    temperature, pressure = float(temperature), float(pressure_Pa)
    vib, imag_cm, imag_vecs = internal_vib_energies(base, H, geometry, return_modes=True)
    # soft imaginary modes (<= IMAG_TOL_CM) are numerical noise on floppy torsions: floored like soft modes.
    # imag_as_soft: the caller has shown by mode following that the larger ones are artefacts too.
    soft = imag_cm if imag_as_soft else imag_cm[imag_cm <= IMAG_TOL_CM]
    n_imag = 0 if imag_as_soft else int(np.sum(imag_cm > IMAG_TOL_CM))   # genuine negative curvature
    mags_real = np.sort(np.concatenate([vib, soft * CM2EV]))
    mags = np.where(mags_real < 50 * CM2EV, 50 * CM2EV, mags_real)   # low-frequency floor
    th = IdealGasThermo(vib_energies=mags, potentialenergy=E_elec, atoms=base,
                        geometry=geometry, symmetrynumber=symmetrynumber,
                        spin=(int(spin) - 1) / 2.0,          # total electronic S = (mult-1)/2
                        vib_selection="all")                 # external modes were projected out above
    G = th.get_gibbs_energy(temperature=temperature, pressure=pressure, verbose=False)
    Gcorr = float((G - E_elec) * EV2KJ)
    if return_info:
        Hcorr = float((th.get_enthalpy(temperature=temperature, verbose=False) - E_elec) * EV2KJ)
        entropy = float(th.get_entropy(temperature=temperature, pressure=pressure, verbose=False) * EV2KJ)
        components = {
            "temperature_K": temperature, "pressure_Pa": pressure,
            "enthalpy_correction_kj": Hcorr, "entropy_kj_per_K": entropy,
            "minus_T_entropy_kj": -temperature * entropy,
            "gibbs_correction_kj": Gcorr,
            "zpe_kj": float(th.get_ZPE_correction() * EV2KJ),
            "n_internal_modes": int(len(mags)),
            "n_floored_modes": int(np.sum(mags_real < 50 * CM2EV)),
            "scope": "Single-geometry ideal-gas thermochemistry; projected RRHO with 50 cm^-1 floor. No solution or ensemble correction.",
        }
        order = np.argsort(-imag_cm) if imag_cm.size else []
        return Gcorr, {"n_imag": n_imag, "max_imag_cm": round(float(imag_cm.max()), 1) if imag_cm.size else 0.0,
                       "thermodynamics": components,
                       "_imag_vecs": [imag_vecs[k] for k in order if imag_cm[k] > IMAG_TOL_CM]}
    return Gcorr


def _write_xyz(path, symbols, coords):
    with open(path, "w") as f:
        f.write(f"{len(symbols)}\n\n")
        for s, (x, y, z) in zip(symbols, np.asarray(coords, float)):
            f.write(f"{s} {x:.6f} {y:.6f} {z:.6f}\n")


def _run_xtb(cmd, d, timeout):
    """Run xtb; a timeout or non-zero exit returns None (the caller drops that conformer) instead of
    raising through ThreadPoolExecutor.map and aborting the whole species/reaction."""
    from metag.timing import timed
    try:
        with timed("xtb.solv"):        # summed CPU-seconds across the solvation pool (divide by workers for wall)
            r = subprocess.run(cmd, cwd=d, env=ENV, capture_output=True, text=True, timeout=timeout)
    except subprocess.TimeoutExpired:
        return None
    if r.returncode != 0:
        return None
    m = re.search(r"TOTAL ENERGY\s+(-?\d+\.\d+)\s+Eh", r.stdout)
    return float(m.group(1)) * HARTREE2KJ if m else None


def dgsolv(symbols, coords, q, mult=1):
    """Vertical ALPB(water) ΔG_solv (kJ/mol, 1 M gas -> 1 M solution) for one geometry:
    E_xtb(GFN2 --sp --alpb water) - E_xtb(GFN2 --sp gas). `mult` sets --uhf (open-shell species, e.g. the
    O2 triplet). Returns None on any xtb failure or timeout.

    ALPB is the production model (2026-10-01): xtb --cosmo has no hydrogen-bond term and under-solvates
    polar groups (FreeSolv per-group error: alcohol OH +17.8, COOH +18.8 kJ/mol vs ALPB +4.3/-4.9)."""
    uhf = ["--uhf", str(int(mult) - 1)]
    with tempfile.TemporaryDirectory() as d:
        xyz = os.path.join(d, "m.xyz")
        _write_xyz(xyz, symbols, coords)
        base = [XTB, xyz, "--gfn", "2", "--chrg", str(int(q)), *uhf, "--sp"]
        eg = _run_xtb(base, d, 180)
        es = _run_xtb(base + ["--alpb", "water"], d, 180)
        return (es - eg) if (es is not None and eg is not None) else None
