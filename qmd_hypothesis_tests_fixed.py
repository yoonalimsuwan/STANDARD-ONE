"""
qmd_hypothesis_tests.py
=======================
Quantum Mental Dynamics (QMD) — Native Differentiable Hypothesis-Test Module.

Operationalizes:
  PAI & Limsuwan, "Quantum Mental Dynamics: A Hierarchical Superposition
  Theory of Cognitive Change, Hidden Informational Variables, and Neural
  State Transitions".

Licence : MIT
Developer : PAI & Limsuwan (MSPS NETWORK)

Design goals
------------
* End-to-end differentiable in native PyTorch (no detached surrogate paths).
* Production training stack: AMP (bf16 / fp16), DDP multi-GPU, gradient
  accumulation, fused AdamW, cosine / one-cycle schedules, EMA weights,
  deterministic seeding, checkpoint / resume, gradient clipping.
* Memory-frugal: Jacobian coupling regulariser via `torch.func` vmap+jacrev
  with automatic fallback to a Hutchinson JVP estimator for large state dims.
* Implements Experiments 1–5 from the paper as testable heads + losses.
* The quantum branch (density operator + POVM instrument) is *conditional*
  and gated by `cfg.enable_quantum`. Completeness Σ_y K_y† K_y = I is enforced
  by construction (differentiable, no Lagrange multipliers).
* Falsifiability is first-class: the module returns per-hypothesis test
  log-likelihood, calibration, parameter counts, and paired bootstrap CIs
  so that a classical baseline can *reject* the quantum extension and vice
  versa.

Author: (research scaffold)
License: MIT

AUDIT FIXES (v1.0.1)
--------------------
[1] LatentInformationalField: the GRUCell attribute `self.prior` shadowed the
    method `prior()`, so lif.prior(Z) recursed forever.  Cell renamed prior_cell.
[2] QuantumInstrument: K_y = M^-1/2 V_y M^-1/2 does NOT satisfy
    sum_y K_y† K_y = I (measured max deviation 0.87).  Correct construction is
    K_y = V_y M^-1/2 (deviation ~2e-7, from the eps jitter only).
[3] CrossLevelTransition(mode="independent"): the (d_x, d_x) mask was
    multiplied with a (d_x, d_in) weight -> shape error; the head also took the
    hierarchy feature h, which mixes all of X and leaks cross-variable
    propagation into the null model.  Head now acts on [X, D, E] with a
    block-diagonal mask on the X columns only.
[4] QMDModel.forward: (a) the observation model predicted D_t from a state
    that had just consumed D_t (copy task, meaningless NLL) -> now predicts from
    the PRIOR state (cfg.obs_from_prior_state=True; set False for old
    behaviour); (b) the NCI attended over t+1 copies of N_t instead of the
    neural history N_0:t; (c) latent_dim must equal d_Z (validated).
[5] jacobian_coupling: vmap closed over batched D/E (shape error); now mapped
    per sample.  Hutchinson fallback estimated the FULL Frobenius energy, not
    the off-diagonal energy; now a two-probe estimator (small upward bias).
[6] HypothesisTestSuite built the Trainer with the base cfg, so the quantum
    variant trained without its quantum loss / DDP unused-parameter flag.
[7] DistributedSampler epoch was never advanced; fused AdamW only on CUDA.
NOT changed (see report): the quantum loss is still a placeholder; the
synthetic data has no temporal coupling; bootstrap CIs advertised in the
docstring are not implemented.
"""

from __future__ import annotations

import argparse
import contextlib
import copy
import json
import math
import os
import random
import time
from dataclasses import dataclass, field, asdict
from typing import Any, Dict, Iterable, List, Optional, Sequence, Tuple

import torch
import torch.nn as nn
import torch.nn.functional as F
from torch import Tensor

# ---------------------------------------------------------------------------
# Torch version / feature shims
# ---------------------------------------------------------------------------
_TV = tuple(int(x) for x in torch.__version__.split("+")[0].split(".")[:2])
_HAS_TORCH_FUNC = hasattr(torch, "func") and hasattr(torch.func, "jacrev") \
    and hasattr(torch.func, "vmap")

try:  # torch >= 2.4
    from torch.amp import autocast as _autocast, GradScaler as _GradScaler
    _AMP_NEW = True
except Exception:  # pragma: no cover
    from torch.cuda.amp import autocast as _autocast, GradScaler as _GradScaler
    _AMP_NEW = False

import torch.distributed as dist
from torch.nn.parallel import DistributedDataParallel as DDP
from torch.utils.data import DataLoader, Dataset
from torch.utils.data.distributed import DistributedSampler


# ---------------------------------------------------------------------------
# Distributed / AMP helpers
# ---------------------------------------------------------------------------
def is_dist() -> bool:
    return dist.is_available() and dist.is_initialized()


def rank() -> int:
    return dist.get_rank() if is_dist() else 0


def world_size() -> int:
    return dist.get_world_size() if is_dist() else 1


def is_main() -> bool:
    return rank() == 0


@contextlib.contextmanager
def no_amp():
    """Disable AMP inside complex / numerically sensitive blocks."""
    if _AMP_NEW:
        with _autocast(device_type="cuda", enabled=False):
            yield
    else:  # pragma: no cover
        with _autocast(enabled=False):
            yield


def amp_ctx(enabled: bool, dtype: torch.dtype):
    if not enabled or not torch.cuda.is_available():
        return contextlib.nullcontext()
    if _AMP_NEW:
        return _autocast(device_type="cuda", dtype=dtype, enabled=True)
    return _autocast(dtype=dtype, enabled=True)  # pragma: no cover


def all_reduce_mean(x: Tensor) -> Tensor:
    if not is_dist():
        return x
    y = x.clone()
    dist.all_reduce(y, op=dist.ReduceOp.SUM)
    return y / world_size()


# ---------------------------------------------------------------------------
# Endless loader iterator (advances DistributedSampler epoch)
# ---------------------------------------------------------------------------
class CyclingIter:
    def __init__(self, loader: DataLoader):
        self.loader = loader
        self.epoch = 0
        self._it = None

    def __iter__(self):
        return self

    def _reset(self) -> None:
        sampler = getattr(self.loader, "sampler", None)
        if isinstance(sampler, DistributedSampler):
            sampler.set_epoch(self.epoch)
        self._it = iter(self.loader)

    def __next__(self):
        if self._it is None:
            self._reset()
        try:
            return next(self._it)
        except StopIteration:
            self.epoch += 1
            self._reset()
            return next(self._it)


# ---------------------------------------------------------------------------
# Config
# ---------------------------------------------------------------------------
@dataclass
class QMDConfig:
    # --- state dimensions -------------------------------------------------
    d_I: int = 32          # Internal Decision State (beliefs, memory, affect, ...)
    d_Z: int = 16          # Latent Informational Field
    d_N: int = 64          # Neural state
    d_E: int = 8           # Environment / task
    d_D: int = 16          # Incoming evidence / observation
    d_Y: int = 16          # Neural-cognitive observable (NCI readout)

    # --- hierarchy --------------------------------------------------------
    n_levels: int = 3
    meta_hidden: int = 128
    n_transition_layers: int = 3
    transition_hidden: int = 256

    # --- latent -----------------------------------------------------------
    latent_dim: int = 16
    latent_hidden: int = 128

    # --- temporal (Frame-Accumulation) ------------------------------------
    kernel_len: int = 16
    kernel_hidden: int = 64

    # --- quantum (conditional) -------------------------------------------
    enable_quantum: bool = False
    quantum_dim: int = 8
    n_outcomes: int = 4

    # --- model variant ----------------------------------------------------
    # "coupled"   : full F_theta with cross-level Jacobian
    # "independent": block-diagonal F_theta (null for H1)
    # "classical" : coupled, no quantum branch (null for H5)
    # "quantum"   : coupled + quantum branch
    mode: str = "coupled"
    # predict D_t from the state BEFORE it consumed D_t (no copy shortcut)
    obs_from_prior_state: bool = True

    # --- loss weights -----------------------------------------------------
    kl_beta: float = 1.0
    coupling_lambda: float = 1e-3
    temporal_lambda: float = 1e-2
    quantum_lambda: float = 1e-2
    reg_lambda: float = 1e-5

    # --- training ---------------------------------------------------------
    batch_size: int = 64
    grad_accum: int = 1
    lr: float = 3e-4
    weight_decay: float = 0.05
    warmup_steps: int = 200
    max_steps: int = 2000
    grad_clip: float = 1.0
    amp_dtype: str = "bf16"        # "bf16" | "fp16" | "off"
    ema_decay: float = 0.999
    seed: int = 0
    device: str = "cuda"
    log_every: int = 50
    eval_every: int = 250
    out_dir: str = "runs/qmd"

    # --- data -------------------------------------------------------------
    seq_len: int = 32
    n_train: int = 4096
    n_val: int = 512
    n_test: int = 512
    data_seed: int = 1234

    def __post_init__(self) -> None:
        if self.latent_dim != self.d_Z:
            raise ValueError(
                f"latent_dim ({self.latent_dim}) must equal d_Z ({self.d_Z}): "
                "Z is written into the (I, Z, N) state slice.")

    def state_dim(self) -> int:
        return self.d_I + self.d_Z + self.d_N


# ---------------------------------------------------------------------------
# Building blocks
# ---------------------------------------------------------------------------
class MLP(nn.Module):
    """Small MLP with GELU + residual option."""
    def __init__(self, in_dim: int, hidden: int, out_dim: int,
                 n_layers: int = 3, residual: bool = False,
                 dropout: float = 0.0):
        super().__init__()
        layers: List[nn.Module] = []
        d = in_dim
        for _ in range(n_layers - 1):
            layers += [nn.Linear(d, hidden), nn.GELU(), nn.Dropout(dropout)]
            d = hidden
        layers += [nn.Linear(d, out_dim)]
        self.net = nn.Sequential(*layers)
        self.residual = residual and in_dim == out_dim

    def forward(self, x: Tensor) -> Tensor:
        y = self.net(x)
        return x + y if self.residual else y


class MetaBaseBlock(nn.Module):
    """
    One recursive rung of the hierarchy:

        H^{(ell)} = H_{M_ell} ⊗ H^{(ell-1)}

    We implement the *effective* action of H_{M_ell} as a learned
    linear map that conditions the base block, i.e.

        h^{(ell)} = tanh( W_M^{ell} h^{(ell-1)} + U^{ell} c )
        h^{(ell-1)} <- h^{(ell-1)} + g^{ell} (h^{(ell)})

    This preserves the "meta conditions base" semantics of the paper
    while keeping parameter growth linear in `n_levels`.
    """
    def __init__(self, d_meta: int, d_ctx: int, hidden: int):
        super().__init__()
        self.to_meta = nn.Linear(d_ctx, d_meta)
        self.merge   = nn.Linear(d_meta, d_meta)
        self.gate    = nn.Linear(d_meta, d_meta)
        self.norm    = nn.LayerNorm(d_meta)

    def forward(self, h: Tensor, ctx: Tensor) -> Tensor:
        m = torch.tanh(self.to_meta(ctx))
        h = self.norm(h + torch.sigmoid(self.gate(m)) * self.merge(m))
        return h


class HierarchicalBackbone(nn.Module):
    """
    Hierarchical meta/base encoder. Produces a context vector h used by the
    transition function and the latent posterior.
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        d_ctx = cfg.state_dim() + cfg.d_D + cfg.d_E
        self.inp = nn.Linear(d_ctx, cfg.meta_hidden)
        self.blocks = nn.ModuleList([
            MetaBaseBlock(cfg.meta_hidden, d_ctx, cfg.meta_hidden)
            for _ in range(cfg.n_levels)
        ])
        self.out = nn.LayerNorm(cfg.meta_hidden)

    def forward(self, x: Tensor, d: Tensor, e: Tensor) -> Tensor:
        ctx = torch.cat([x, d, e], dim=-1)
        h = F.gelu(self.inp(ctx))
        for blk in self.blocks:
            h = blk(h, ctx)
        return self.out(h)


# ---------------------------------------------------------------------------
# Frame-Accumulation Hypothesis (temporal integration)
# ---------------------------------------------------------------------------
class FrameAccumulation(nn.Module):
    """
    Learnable temporal integration kernel:

        P_n = Σ_{j=0..J} w_j  s_{n-j}

    with w_j produced by a small hyper-network conditioned on attention /
    context. Supports a recurrent state for more expressive kernels.
    """
    def __init__(self, cfg: QMDConfig, d_signal: int):
        super().__init__()
        self.K = cfg.kernel_len
        self.d_signal = d_signal
        self.hyper = MLP(cfg.d_E, cfg.kernel_hidden, cfg.kernel_len, n_layers=2)
        self.mix = nn.Linear(d_signal, d_signal, bias=False)
        # recurrent refinement
        self.gru = nn.GRUCell(d_signal, d_signal)

    def forward(self, s: Tensor, ctx: Tensor) -> Tuple[Tensor, Tensor]:
        # s:    (B, T, d_signal)
        # ctx:  (B, d_E)
        B, T, D = s.shape
        K = min(self.K, T)
        w = torch.softmax(self.hyper(ctx), dim=-1)[:, :K]          # (B, K)
        # build shifted windows
        idx = torch.arange(T, device=s.device).unsqueeze(0)         # (1, T)
        off = torch.arange(K, device=s.device).unsqueeze(1)         # (K, 1)
        pos = (idx - off).clamp(min=0)                              # (K, T)
        # gather: (B, K, T, D)
        gathered = s[:, pos, :]                                     # (B, K, T, D)
        P = torch.einsum("bk,bktd->btd", w, gathered)               # (B, T, D)
        P = self.mix(P)
        # recurrent pass
        h = torch.zeros(B, D, device=s.device, dtype=P.dtype)
        outs = []
        for t in range(T):
            h = self.gru(P[:, t, :], h)
            outs.append(h)
        P = torch.stack(outs, dim=1)                                # (B, T, D)
        return P, w


# ---------------------------------------------------------------------------
# Latent Informational Field (amortised VI)
# ---------------------------------------------------------------------------
class LatentInformationalField(nn.Module):
    """
    q(Z_t | Z_{t-1}, I_{t-1}, N_{t-1}, D_t)   (amortised posterior)
    p(Z_t | Z_{t-1})                          (learned prior)
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        self.cfg = cfg
        d_in = cfg.latent_dim + cfg.state_dim() + cfg.d_D
        self.post = MLP(d_in, cfg.latent_hidden, 2 * cfg.latent_dim, n_layers=3)
        self.prior_cell = nn.GRUCell(cfg.latent_dim, cfg.latent_dim)

    def posterior(self, z_prev: Tensor, x_prev: Tensor, d_t: Tensor
                  ) -> Tuple[Tensor, Tensor]:
        h = torch.cat([z_prev, x_prev, d_t], dim=-1)
        mu, logvar = self.post(h).chunk(2, dim=-1)
        logvar = logvar.clamp(min=-8.0, max=4.0)
        return mu, logvar

    def prior(self, z_prev: Tensor) -> Tuple[Tensor, Tensor]:
        h = self.prior_cell(z_prev)
        mu = torch.tanh(h)
        logvar = torch.zeros_like(mu)
        return mu, logvar

    @staticmethod
    def reparameterise(mu: Tensor, logvar: Tensor) -> Tensor:
        std = torch.exp(0.5 * logvar)
        eps = torch.randn_like(std)
        return mu + eps * std

    @staticmethod
    def kl(mu_q: Tensor, lv_q: Tensor, mu_p: Tensor, lv_p: Tensor) -> Tensor:
        kl = 0.5 * (lv_p - lv_q
                    + (torch.exp(lv_q) + (mu_q - mu_p).pow(2))
                    / torch.exp(lv_p).clamp_min(1e-6)
                    - 1.0)
        return kl.sum(-1)


# ---------------------------------------------------------------------------
# Neural-Cognitive Interface (NCI)
# ---------------------------------------------------------------------------
class NeuralCognitiveInterface(nn.Module):
    """
    I_t ~ p(I_t | N_{0:t}, D_{0:t}, E_{0:t})   (effective mapping).
    We implement it as a small cross-attention readout from neural to
    cognitive state, plus an observation head for the neural-cognitive
    correspondence experiment (E4).
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        self.q = nn.Linear(cfg.d_I, cfg.meta_hidden)
        self.k = nn.Linear(cfg.d_N, cfg.meta_hidden)
        self.v = nn.Linear(cfg.d_N, cfg.meta_hidden)
        self.proj = nn.Linear(cfg.meta_hidden, cfg.d_I)
        self.obs_head = MLP(cfg.d_I + cfg.d_N, cfg.meta_hidden, cfg.d_Y, n_layers=2)

    def forward(self, I: Tensor, N: Tensor) -> Tuple[Tensor, Tensor]:
        # I: (B, d_I), N: (B, T, d_N)
        q = self.q(I).unsqueeze(1)                       # (B, 1, H)
        k = self.k(N)                                    # (B, T, H)
        v = self.v(N)
        attn = torch.softmax(q @ k.transpose(-1, -2) / math.sqrt(k.size(-1)), dim=-1)
        ctx = (attn @ v).squeeze(1)                      # (B, H)
        I_new = I + self.proj(ctx)
        # pooled neural for observation head
        N_pool = N.mean(dim=1)
        Y = self.obs_head(torch.cat([I_new, N_pool], dim=-1))
        return I_new, Y


# ---------------------------------------------------------------------------
# Quantum branch (conditional, differentiable)
# ---------------------------------------------------------------------------
class QuantumInstrument(nn.Module):
    """
    Differentiable POVM instrument {K_y} with Σ_y K_y† K_y = I enforced by
    construction. Parameterised as in the paper:

        K_y = K_y(g_B, g_M, g_{MB}, g_I)

    We implement each K_y as an unconstrained complex linear map V_y, then
    project via the polar factor:

        M = Σ_y V_y† V_y + eps I
        K_y = V_y M^{-1/2}        =>  Σ_y K_y† K_y = M^{-1/2} M M^{-1/2} ≈ I
    """
    def __init__(self, dim: int, n_outcomes: int, cfg: QMDConfig):
        super().__init__()
        self.dim = dim
        self.n_outcomes = n_outcomes
        self.cfg = cfg
        # real/imag channels (AMP-friendly: real params, complex at runtime)
        self.W = nn.Parameter(torch.randn(n_outcomes, dim, dim, 2) * (1.0 / math.sqrt(dim)))

    def _K(self) -> Tensor:
        with no_amp():
            W = torch.view_as_complex(self.W.float().contiguous())     # (Y, d, d)
            M = torch.einsum("yij,yik->jk", W.conj(), W)               # (d, d)
            I = torch.eye(self.dim, dtype=M.dtype, device=M.device)
            M = M + 1e-6 * I
            # Hermitian eigendecomposition -> M^{-1/2}
            evals, evecs = torch.linalg.eigh(M)
            evals = evals.clamp_min(1e-8)
            M_inv_sqrt = (evecs * evals.rsqrt().unsqueeze(-2)) @ evecs.conj().transpose(-1, -2)
            K = W @ M_inv_sqrt.unsqueeze(0)                            # (Y, d, d)
            return K

    def forward(self, rho: Tensor) -> Tensor:
        """
        rho : (B, d, d) complex Hermitian density operators.
        returns:
            probs : (B, Y)
            post  : (B, Y, d, d) post-measurement states
        """
        K = self._K()                                        # (Y, d, d)
        # K rho K^†  -> (B, Y, d, d)
        Kr = torch.einsum("yij,bjk->byik", K, rho)
        KrK = torch.einsum("byij,ylj->byil", Kr, K.conj())   # (B, Y, d, d)
        probs = torch.einsum("byii->by", KrK).real.clamp_min(1e-12)
        post = KrK / probs.unsqueeze(-1).unsqueeze(-1)
        return probs, post


class DensityOperator(nn.Module):
    """
    Produces a valid density operator from a hidden state:

        rho = A A† / Tr(A A†)
    """
    def __init__(self, in_dim: int, d_q: int):
        super().__init__()
        self.d_q = d_q
        self.proj = nn.Linear(in_dim, d_q * d_q * 2)

    def forward(self, h: Tensor) -> Tensor:
        with no_amp():
            B = h.size(0)
            A = self.proj(h.float()).view(B, self.d_q, self.d_q, 2)
            A = torch.view_as_complex(A.contiguous())            # (B, d, d)
            rho = A @ A.conj().transpose(-1, -2)
            tr = torch.einsum("bii->b", rho).real.clamp_min(1e-8)
            return rho / tr.unsqueeze(-1).unsqueeze(-1)


# ---------------------------------------------------------------------------
# Cross-level transition
# ---------------------------------------------------------------------------
class CrossLevelTransition(nn.Module):
    """
    X_{t+1} = F_theta(X_t, D_t, E_t) + xi_t

    For `mode == "independent"`, F is block-diagonal on (I, Z, N) — the
    null hypothesis for H1 (no cross-variable propagation).
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        self.cfg = cfg
        d_x = cfg.state_dim()
        d_in = d_x + cfg.d_D + cfg.d_E + cfg.meta_hidden
        self.backbone = HierarchicalBackbone(cfg)
        self.trunk = MLP(d_in, cfg.transition_hidden, 2 * d_x,
                         n_layers=cfg.n_transition_layers)
        if cfg.mode == "independent":
            # block-diagonal linear head on [X, D, E]: X columns are masked to
            # the (I, Z, N) diagonal blocks, exogenous D / E are unrestricted.
            # The hierarchy feature h is NOT used here: it mixes all of X.
            self.block_head = nn.Linear(d_x + cfg.d_D + cfg.d_E, d_x)
            self.register_buffer("_block_mask", self._make_block_mask(cfg), persistent=False)

    @staticmethod
    def _make_block_mask(cfg: QMDConfig) -> Tensor:
        d = cfg.state_dim()
        mask = torch.ones(d, d + cfg.d_D + cfg.d_E)
        mask[:, :d] = 0.0                       # X columns: diagonal blocks only
        s = [0, cfg.d_I, cfg.d_I + cfg.d_Z, d]
        for a in range(3):
            mask[s[a]:s[a+1], s[a]:s[a+1]] = 1.0
        return mask

    def forward(self, X: Tensor, D: Tensor, E: Tensor) -> Tuple[Tensor, Tensor]:
        h = self.backbone(X, D, E)
        inp = torch.cat([X, D, E, h], dim=-1)
        out = self.trunk(inp)
        mu, logvar = out.chunk(2, dim=-1)
        logvar = logvar.clamp(min=-10.0, max=4.0)
        if self.cfg.mode == "independent":
            # block-diagonalise via mask (acts on [X, D, E])
            W = self.block_head.weight * self._block_mask.to(self.block_head.weight.dtype)
            mu = F.linear(torch.cat([X, D, E], dim=-1), W, self.block_head.bias)
        return mu, logvar


# ---------------------------------------------------------------------------
# QMD model
# ---------------------------------------------------------------------------
class QMDModel(nn.Module):
    """
    Top-level QMD model. Given a sequence of evidence D_{1:T} and context
    E_{1:T}, it rolls out the coupled state X_t = (I_t, Z_t, N_t), infers
    latent Z_t via amortised VI, produces NCI observations Y_t, and — if
    enabled — generates quantum outcomes via the POVM instrument.
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        self.cfg = cfg
        d_x = cfg.state_dim()

        self.transition = CrossLevelTransition(cfg)
        self.lif = LatentInformationalField(cfg)
        self.nci = NeuralCognitiveInterface(cfg)

        # encoder: D_t -> initial state
        self.encoder = MLP(cfg.d_D + cfg.d_E, cfg.transition_hidden, d_x,
                           n_layers=2)

        # observation head: p(D_t | X_t, E_t)
        self.obs = MLP(d_x + cfg.d_E, cfg.transition_hidden, 2 * cfg.d_D,
                       n_layers=2)

        # Frame-Accumulation
        self.fah = FrameAccumulation(cfg, d_signal=cfg.d_D)

        # Quantum (conditional)
        if cfg.enable_quantum:
            self.rho = DensityOperator(d_x + cfg.meta_hidden, cfg.quantum_dim)
            self.instrument = QuantumInstrument(cfg.quantum_dim, cfg.n_outcomes, cfg)
            self.q_head = nn.Linear(cfg.quantum_dim * cfg.quantum_dim * 2, cfg.n_outcomes)

    # ------------------------------------------------------------------
    def _split(self, X: Tensor) -> Tuple[Tensor, Tensor, Tensor]:
        i = self.cfg.d_I
        z = i + self.cfg.d_Z
        return X[..., :i], X[..., i:z], X[..., z:]

    # ------------------------------------------------------------------
    def forward(
        self,
        D: Tensor,            # (B, T, d_D) — evidence / observations
        E: Tensor,            # (B, T, d_E) — environment / task context
        *,
        sample: bool = True,
    ) -> Dict[str, Tensor]:
        B, T, _ = D.shape
        cfg = self.cfg

        # initial state (D_0 is withheld when the observation model must be
        # causal; otherwise p(D_0 | X_0) would be a copy task)
        D0 = torch.zeros_like(D[:, 0]) if cfg.obs_from_prior_state else D[:, 0]
        X = torch.tanh(self.encoder(torch.cat([D0, E[:, 0]], dim=-1)))
        Z = torch.zeros(B, cfg.latent_dim, device=D.device, dtype=D.dtype)

        # Frame-Accumulation perceptual representation
        P, w = self.fah(D, E[:, 0])                          # (B, T, d_D), (B, K)

        # collect
        Xs, Zs, Ys, D_hat, Kls, Xis = [], [], [], [], [], []
        N_hist: List[Tensor] = []                             # neural history

        for t in range(T):
            X_prev = X                                        # state before D_t
            # ---- latent inference -----------------------------------
            mu_q, lv_q = self.lif.posterior(Z, X, D[:, t])
            mu_p, lv_p = self.lif.prior(Z)
            kl = self.lif.kl(mu_q, lv_q, mu_p, lv_p)          # (B,)
            Z_new = self.lif.reparameterise(mu_q, lv_q) if sample else mu_q
            Z = Z_new

            # ---- transition -----------------------------------------
            # we fold Z into the transition via re-injection:
            X_in = X.clone()
            X_in[..., cfg.d_I:cfg.d_I + cfg.d_Z] = Z
            mu_x, lv_x = self.transition(X_in, D[:, t], E[:, t])
            xi = torch.randn_like(mu_x) * torch.exp(0.5 * lv_x)
            X_next = mu_x + (xi if sample else 0.0)
            X = X_next

            # ---- NCI ------------------------------------------------
            I, _, N = self._split(X)
            N_seq = torch.stack(N_hist + [N], dim=1)          # (B, t+1, d_N)
            I_new, Y = self.nci(I, N_seq)
            N_hist.append(N)
            X = torch.cat([I_new, X[..., cfg.d_I:]], dim=-1)

            # ---- observation model ----------------------------------
            X_obs = X_prev if cfg.obs_from_prior_state else X
            out = self.obs(torch.cat([X_obs, E[:, t]], dim=-1))
            mu_d, lv_d = out.chunk(2, dim=-1)
            lv_d = lv_d.clamp(min=-8.0, max=4.0)
            d_hat = mu_d

            Xs.append(X); Zs.append(Z); Ys.append(Y)
            D_hat.append(mu_d); Kls.append(kl)
            Xis.append(torch.exp(0.5 * lv_d))

        out = {
            "X": torch.stack(Xs, dim=1),                      # (B, T, d_X)
            "Z": torch.stack(Zs, dim=1),                      # (B, T, d_Z)
            "Y": torch.stack(Ys, dim=1),                      # (B, T, d_Y)
            "D_hat": torch.stack(D_hat, dim=1),               # (B, T, d_D)
            "D_logstd": torch.log(torch.stack(Xis, dim=1) + 1e-6),
            "kl": torch.stack(Kls, dim=1),                    # (B, T)
            "P": P,                                           # (B, T, d_D)
            "kernel_w": w,                                    # (B, K)
        }

        # ---- quantum branch (conditional) ---------------------------
        if cfg.enable_quantum:
            h = self.transition.backbone(Xs[-1], D[:, -1], E[:, -1])
            rho = self.rho(torch.cat([Xs[-1], h], dim=-1))    # (B, d_q, d_q)
            probs, post = self.instrument(rho)                # (B, Y), (B, Y, d, d)
            out["rho"] = rho
            out["q_probs"] = probs
            out["q_post"] = post

        return out

    # ------------------------------------------------------------------
    def jacobian_coupling(self, X: Tensor, D: Tensor, E: Tensor) -> Tensor:
        """
        Off-diagonal Jacobian energy  ||J - diag(J)||_F^2  per sample.
        Uses torch.func vmap+jacrev when available; falls back to Hutchinson.
        """
        if _HAS_TORCH_FUNC and X.numel() < 1 << 18:
            def f(x, d_, e_):
                mu, _ = self.transition(x.unsqueeze(0), d_.unsqueeze(0),
                                        e_.unsqueeze(0))
                return mu.squeeze(0)
            # D and E are per-sample, so vmap must map them together with X
            J = torch.func.vmap(torch.func.jacrev(f), randomness="same")(
                X, D, E)                                       # (B, d, d)
            diag = torch.diagonal(J, dim1=-2, dim2=-1)         # (B, d)
            off = J.pow(2).sum(dim=(-2, -1)) - diag.pow(2).sum(-1)
            return off
        # Hutchinson fallback: two independent Rademacher probes.
        #   d_hat = v1 ⊙ J v1           (E = diag(J))
        #   ||(J - diag(d_hat)) v2||²   (≈ ||J - diag(J)||_F², small upward bias)
        def f(x):
            mu, _ = self.transition(x, D, E)
            return mu
        eps = 1e-3

        def jvp(v: Tensor) -> Tensor:          # central finite-difference J v
            return (f(X + eps * v) - f(X - eps * v)) / (2 * eps)

        v1 = torch.randint_like(X, 0, 2) * 2 - 1
        d_hat = v1 * jvp(v1)
        v2 = torch.randint_like(X, 0, 2) * 2 - 1
        return (jvp(v2) - d_hat * v2).pow(2).sum(-1)

# ---------------------------------------------------------------------------
# Dataset (synthetic — swap for real behavioural/neural data)
# ---------------------------------------------------------------------------
class SyntheticQMDDataset(Dataset):
    """
    Generates sequences with a *known* cross-variable coupling structure so
    that H1 (coupling) and H2 (latent) can be sanity-checked. Replace this
    with your behavioural / neural data loader for real experiments.
    """
    def __init__(self, cfg: QMDConfig, n: int, seed: int):
        g = torch.Generator().manual_seed(seed)
        B = n
        T = cfg.seq_len
        # latent driver
        z = torch.randn(B, T, cfg.latent_dim, generator=g)
        # evidence is a nonlinear mixture of z + noise
        W = torch.randn(cfg.latent_dim, cfg.d_D, generator=g) / math.sqrt(cfg.latent_dim)
        D = torch.tanh(z @ W) + 0.3 * torch.randn(B, T, cfg.d_D, generator=g)
        # context
        E = 0.5 * torch.randn(B, T, cfg.d_E, generator=g)
        self.D, self.E, self.z = D, E, z

    def __len__(self): return self.D.size(0)

    def __getitem__(self, i):
        return {"D": self.D[i], "E": self.E[i], "z": self.z[i]}


# ---------------------------------------------------------------------------
# Loss
# ---------------------------------------------------------------------------
class QMDLoss(nn.Module):
    """
    Composite differentiable loss.

        L = NLL(D | X)                    (observation)
          + β · KL(q(Z) || p(Z))          (variational)
          + λ_c · ||J - diag(J)||_F²       (cross-level coupling regulariser)
          + λ_t · MSE(P, D)                (frame-accumulation)
          + λ_q · NLL(y | ρ)               (Born rule, quantum only)
          + λ_r · ||θ||²                   (weight decay surrogate)
    """
    def __init__(self, cfg: QMDConfig):
        super().__init__()
        self.cfg = cfg

    def forward(self, batch: Dict[str, Tensor], out: Dict[str, Tensor],
                model: QMDModel) -> Dict[str, Tensor]:
        cfg = self.cfg
        D = batch["D"]; E = batch["E"]

        # 1. observation NLL (Gaussian)
        mu = out["D_hat"]; log_sigma = out["D_logstd"]
        nll = 0.5 * ((D - mu).pow(2) / log_sigma.exp().pow(2)
                     + 2.0 * log_sigma + math.log(2 * math.pi))
        nll = nll.mean()

        # 2. KL
        kl = out["kl"].mean()

        # 3. coupling regulariser (Jacobian off-diagonal energy)
        #    Use a subset of timesteps to bound memory.
        X = out["X"]
        T = X.size(1)
        idx = torch.linspace(0, T - 1, steps=min(T, 4)).long().to(X.device)
        off = []
        for t in idx:
            off.append(model.jacobian_coupling(X[:, t], D[:, t], E[:, t]))
        coupling = torch.stack(off, dim=0).mean()

        # 4. temporal (Frame-Accumulation)
        P = out["P"]
        temporal = F.mse_loss(P, D)

        # 5. quantum (Born rule)
        quantum = torch.tensor(0.0, device=D.device, dtype=D.dtype)
        if cfg.enable_quantum and "q_probs" in out:
            # uninformative prior over outcomes; we fit the model to a
            # *learned* target distribution derived from the observation
            # (this is the falsifiable link: if the Born rule adds no signal,
            # the classical baseline matches it).
            target = F.softmax(out["q_probs"].detach(), dim=-1)  # placeholder
            quantum = -(target * torch.log(out["q_probs"] + 1e-12)).sum(-1).mean()

        # 6. weight decay surrogate
        reg = sum(p.pow(2).sum() for p in model.parameters() if p.requires_grad)

        total = (nll
                 + cfg.kl_beta * kl
                 + cfg.coupling_lambda * coupling
                 + cfg.temporal_lambda * temporal
                 + cfg.quantum_lambda * quantum
                 + cfg.reg_lambda * reg)

        return {
            "loss": total,
            "nll": nll.detach(),
            "kl": kl.detach(),
            "coupling": coupling.detach(),
            "temporal": temporal.detach(),
            "quantum": quantum.detach() if isinstance(quantum, Tensor) else quantum,
            "reg": reg.detach(),
        }


# ---------------------------------------------------------------------------
# EMA
# ---------------------------------------------------------------------------
class EMA:
    def __init__(self, model: nn.Module, decay: float):
        self.decay = decay
        self.shadow = {k: v.detach().clone() for k, v in model.state_dict().items()}

    @torch.no_grad()
    def update(self, model: nn.Module):
        for k, v in model.state_dict().items():
            if v.dtype.is_floating_point:
                self.shadow[k].mul_(self.decay).add_(v.detach(), alpha=1 - self.decay)
            else:
                self.shadow[k].copy_(v)

    def copy_to(self, model: nn.Module):
        model.load_state_dict(self.shadow, strict=False)


# ---------------------------------------------------------------------------
# Trainer
# ---------------------------------------------------------------------------
class Trainer:
    def __init__(self, cfg: QMDConfig, model: QMDModel, device: torch.device):
        self.cfg = cfg
        self.device = device
        self.model = model.to(device)
        if is_dist():
            self.model = DDP(self.model, device_ids=[device.index],
                             find_unused_parameters=cfg.enable_quantum)
        self.loss_fn = QMDLoss(cfg)
        self.opt = torch.optim.AdamW(
            [p for p in self.model.parameters() if p.requires_grad],
            lr=cfg.lr, weight_decay=cfg.weight_decay,
            betas=(0.9, 0.95), fused=(device.type == "cuda"),
        )
        self.scaler = _GradScaler(enabled=(cfg.amp_dtype == "fp16"))
        self.ema = EMA(self._unwrapped(), cfg.ema_decay)
        self.step = 0

    def _unwrapped(self) -> nn.Module:
        return self.model.module if isinstance(self.model, DDP) else self.model

    # ------------------------------------------------------------------
    def _lr(self) -> float:
        cfg = self.cfg
        if self.step < cfg.warmup_steps:
            return cfg.lr * (self.step + 1) / max(1, cfg.warmup_steps)
        prog = (self.step - cfg.warmup_steps) / max(1, cfg.max_steps - cfg.warmup_steps)
        return 0.5 * cfg.lr * (1.0 + math.cos(math.pi * min(1.0, prog)))

    def _amp_dtype(self) -> torch.dtype:
        return {"bf16": torch.bfloat16, "fp16": torch.float16,
                "off": torch.float32}[self.cfg.amp_dtype]

    # ------------------------------------------------------------------
    def train_step(self, batch: Dict[str, Tensor]) -> Dict[str, float]:
        cfg = self.cfg
        self.model.train()
        D = batch["D"].to(self.device, non_blocking=True)
        E = batch["E"].to(self.device, non_blocking=True)
        batch = {"D": D, "E": E}

        lr = self._lr()
        for g in self.opt.param_groups:
            g["lr"] = lr

        with amp_ctx(cfg.amp_dtype != "off", self._amp_dtype()):
            out = self.model(D, E, sample=True)
            losses = self.loss_fn(batch, out, self._unwrapped())
            loss = losses["loss"] / cfg.grad_accum

        self.scaler.scale(loss).backward()

        if (self.step + 1) % cfg.grad_accum == 0:
            self.scaler.unscale_(self.opt)
            torch.nn.utils.clip_grad_norm_(
                [p for p in self.model.parameters() if p.requires_grad],
                cfg.grad_clip,
            )
            self.scaler.step(self.opt)
            self.scaler.update()
            self.opt.zero_grad(set_to_none=True)
            self.ema.update(self._unwrapped())

        self.step += 1
        return {k: float(v) for k, v in losses.items() if v.numel() == 1}

    # ------------------------------------------------------------------
    @torch.no_grad()
    def evaluate(self, loader: DataLoader) -> Dict[str, float]:
        self.model.eval()
        tot = {"nll": 0.0, "kl": 0.0, "coupling": 0.0, "temporal": 0.0,
               "quantum": 0.0, "n": 0}
        for batch in loader:
            D = batch["D"].to(self.device, non_blocking=True)
            E = batch["E"].to(self.device, non_blocking=True)
            with amp_ctx(self.cfg.amp_dtype != "off", self._amp_dtype()):
                out = self.model(D, E, sample=False)
                losses = self.loss_fn({"D": D, "E": E}, out, self._unwrapped())
            bs = D.size(0)
            for k in ("nll", "kl", "coupling", "temporal", "quantum"):
                tot[k] += float(losses[k]) * bs
            tot["n"] += bs
        for k in ("nll", "kl", "coupling", "temporal", "quantum"):
            tot[k] /= max(1, tot["n"])
        # DDP: average across ranks
        if is_dist():
            for k in ("nll", "kl", "coupling", "temporal", "quantum"):
                t = torch.tensor(tot[k], device=self.device)
                tot[k] = float(all_reduce_mean(t))
        return tot

    # ------------------------------------------------------------------
    def state_dict(self) -> Dict[str, Any]:
        return {
            "model": self._unwrapped().state_dict(),
            "opt": self.opt.state_dict(),
            "scaler": self.scaler.state_dict(),
            "ema": self.ema.shadow,
            "step": self.step,
        }

    def load_state_dict(self, sd: Dict[str, Any]):
        self._unwrapped().load_state_dict(sd["model"])
        self.opt.load_state_dict(sd["opt"])
        self.scaler.load_state_dict(sd["scaler"])
        self.ema.shadow = sd["ema"]
        self.step = sd["step"]


# ---------------------------------------------------------------------------
# Hypothesis-testing suite (Experiments 1–5)
# ---------------------------------------------------------------------------
class HypothesisTestSuite:
    """
    Runs the falsifiability program from Section 13 of the paper:

      E1  Cross-variable propagation  : coupled vs. independent
      E2  Latent informational field  : with vs. without latent Z
      E3  Temporal integration        : FAH vs. feed-forward baseline
      E4  Neural-cognitive interface  : NCI vs. direct readout
      E5  Quantum-specific evidence   : classical vs. quantum variant

    Reports per-hypothesis test log-likelihood, parameter count,
    and paired bootstrap CI on the difference.
    """
    def __init__(self, cfg: QMDConfig, device: torch.device):
        self.cfg = cfg
        self.device = device

    def _build(self, mode: str, enable_quantum: bool) -> QMDModel:
        c = copy.deepcopy(self.cfg)
        c.mode = mode
        c.enable_quantum = enable_quantum
        return QMDModel(c).to(self.device)

    def _fit_and_score(self, model: QMDModel, train_loader: DataLoader,
                       test_loader: DataLoader, steps: int) -> Dict[str, float]:
        cfg = self.cfg
        tr = Trainer(model.cfg, model, self.device)   # model's own cfg
        tr.cfg.max_steps = steps
        data_iter = CyclingIter(train_loader)
        t0 = time.time()
        for _ in range(steps):
            batch = next(data_iter)
            tr.train_step(batch)
        # use EMA weights for evaluation
        ema_model = copy.deepcopy(tr._unwrapped())
        tr.ema.copy_to(ema_model)
        ev = Trainer(model.cfg, ema_model, self.device)
        metrics = ev.evaluate(test_loader)
        metrics["params"] = sum(p.numel() for p in model.parameters() if p.requires_grad)
        metrics["wall_s"] = time.time() - t0
        return metrics

    def run(self, train_loader: DataLoader, test_loader: DataLoader,
            steps: int) -> Dict[str, Dict[str, float]]:
        variants = {
            "H1_coupled":      self._build("coupled", False),
            "H1_independent":  self._build("independent", False),
            "H5_classical":    self._build("coupled", False),
            "H5_quantum":      self._build("coupled", True),
        }
        results: Dict[str, Dict[str, float]] = {}
        for name, model in variants.items():
            if is_main():
                print(f"[suite] fitting {name} ...")
            results[name] = self._fit_and_score(model, train_loader, test_loader, steps)

        # pairwise deltas (test NLL)
        def delta(a: str, b: str) -> Dict[str, float]:
            return {
                "dNLL": results[a]["nll"] - results[b]["nll"],
                "dParams": results[a]["params"] - results[b]["params"],
            }
        results["_delta_H1"] = delta("H1_independent", "H1_coupled")
        results["_delta_H5"] = delta("H5_classical", "H5_quantum")
        return results


# ---------------------------------------------------------------------------
# DDP setup / teardown
# ---------------------------------------------------------------------------
def setup_dist(backend: str = "nccl") -> Tuple[torch.device, int, int]:
    if "RANK" in os.environ and "WORLD_SIZE" in os.environ:
        dist.init_process_group(backend=backend)
        r = dist.get_rank()
        ws = dist.get_world_size()
        local = int(os.environ.get("LOCAL_RANK", r))
        torch.cuda.set_device(local)
        return torch.device("cuda", local), r, ws
    return torch.device("cuda" if torch.cuda.is_available() else "cpu"), 0, 1


def cleanup_dist():
    if is_dist():
        dist.barrier()
        dist.destroy_process_group()


def seed_all(seed: int):
    random.seed(seed)
    torch.manual_seed(seed)
    torch.cuda.manual_seed_all(seed)


# ---------------------------------------------------------------------------
# Main
# ---------------------------------------------------------------------------
def build_loaders(cfg: QMDConfig, device: torch.device
                  ) -> Tuple[DataLoader, DataLoader, DataLoader]:
    tr = SyntheticQMDDataset(cfg, cfg.n_train, cfg.data_seed)
    va = SyntheticQMDDataset(cfg, cfg.n_val, cfg.data_seed + 1)
    te = SyntheticQMDDataset(cfg, cfg.n_test, cfg.data_seed + 2)
    sampler = DistributedSampler(tr) if is_dist() else None
    common = dict(num_workers=2, pin_memory=True, persistent_workers=False)
    return (
        DataLoader(tr, batch_size=cfg.batch_size, sampler=sampler,
                   shuffle=(sampler is None), drop_last=True, **common),
        DataLoader(va, batch_size=cfg.batch_size, shuffle=False, **common),
        DataLoader(te, batch_size=cfg.batch_size, shuffle=False, **common),
    )


def parse_args() -> argparse.Namespace:
    p = argparse.ArgumentParser("QMD hypothesis tests")
    p.add_argument("--mode", choices=["train", "compare"], default="compare")
    p.add_argument("--config", type=str, default=None)
    p.add_argument("--steps", type=int, default=None)
    p.add_argument("--quantum", action="store_true")
    p.add_argument("--out", type=str, default=None)
    return p.parse_args()


def main():
    args = parse_args()
    device, r, ws = setup_dist()
    seed_all(0)

    cfg = QMDConfig()
    if args.config:
        with open(args.config) as f:
            cfg = QMDConfig(**json.load(f))
    if args.steps is not None:
        cfg.max_steps = args.steps
    if args.out:
        cfg.out_dir = args.out
    cfg.device = str(device)
    cfg.enable_quantum = cfg.enable_quantum or args.quantum

    os.makedirs(cfg.out_dir, exist_ok=True)
    train_loader, val_loader, test_loader = build_loaders(cfg, device)

    if args.mode == "train":
        model = QMDModel(cfg)
        tr = Trainer(cfg, model, device)
        data_iter = CyclingIter(train_loader)
        t0 = time.time()
        for _ in range(cfg.max_steps):
            batch = next(data_iter)
            logs = tr.train_step(batch)
            if is_main() and tr.step % cfg.log_every == 0:
                print(f"step {tr.step:6d} | " +
                      " ".join(f"{k}={v:.4f}" for k, v in logs.items()) +
                      f" | lr={tr._lr():.2e} | {time.time()-t0:.1f}s")
            if is_main() and tr.step % cfg.eval_every == 0:
                ev = tr.evaluate(val_loader)
                print(f"  [val] " + " ".join(f"{k}={v:.4f}" for k, v in ev.items()))
        if is_main():
            torch.save(tr.state_dict(), os.path.join(cfg.out_dir, "ckpt.pt"))
    else:  # compare
        suite = HypothesisTestSuite(cfg, device)
        results = suite.run(train_loader, test_loader, steps=cfg.max_steps)
        if is_main():
            print(json.dumps(results, indent=2))
            with open(os.path.join(cfg.out_dir, "hypothesis_results.json"), "w") as f:
                json.dump(results, f, indent=2)

    cleanup_dist()


if __name__ == "__main__":
    main()
