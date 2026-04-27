from __future__ import annotations

import math

import mlx.core as mx
import mlx.optimizers as optim
import numpy as np
from mlx.utils import tree_flatten, tree_unflatten

from .config import CONTROL_TENSOR_NAME_PATTERNS, Hyperparameters
from .model import GPT


def token_chunks(total_tokens: int, seq_len: int, max_chunk_tokens: int) -> list[int]:
    # Split a token budget into sequence-aligned chunks. This is purely a memory
    # control mechanism: the caller still processes the same effective number of
    # tokens, just in smaller pieces that are safer for MLX's lazy execution and
    # unified-memory pressure. The rounding logic deliberately preserves whole
    # sequences so later reshape operations stay simple.
    usable_total = (total_tokens // seq_len) * seq_len
    if usable_total <= 0:
        raise ValueError(f"token budget too small for seq_len={seq_len}")
    usable_chunk = max((max_chunk_tokens // seq_len) * seq_len, seq_len)
    chunks: list[int] = []
    remaining = usable_total
    while remaining > 0:
        chunk = min(remaining, usable_chunk)
        chunks.append(chunk)
        remaining -= chunk
    return chunks


def accumulate_flat_grads(
    accum: dict[str, mx.array] | None,
    grads_tree: dict,
    scale: float,
) -> dict[str, mx.array]:
    # MLX model state is naturally flattened when applying grouped optimizer
    # updates, so gradient accumulation follows the same representation. That
    # avoids repeatedly rebuilding nested trees during inner-loop accumulation.
    # A future refactor could wrap this in a small gradient-buffer object for
    # better type clarity, but the flat dict keeps the hot path easy to inspect.
    flat = dict(tree_flatten(grads_tree))
    if accum is None:
        return {k: g * scale for k, g in flat.items()}
    for k, g in flat.items():
        accum[k] = accum[k] + g * scale
    return accum


def zeropower_newtonschulz5(g: mx.array, steps: int, eps: float = 1e-7) -> mx.array:
    # Orthogonalize a 2D update matrix with a fast Newton-Schulz iteration.
    # Muon uses this to normalize matrix-shaped gradients before applying them.
    # Background on Muon: https://kellerjordan.github.io/posts/muon/
    a, b, c = 3.4445, -4.7750, 2.0315
    x = g.astype(mx.float32)
    x = x / (mx.sqrt(mx.sum(x * x)) + eps)
    transposed = x.shape[0] > x.shape[1]
    if transposed:
        x = x.T
    for _ in range(steps):
        a_mat = x @ x.T
        b_mat = b * a_mat + c * (a_mat @ a_mat)
        x = a * x + b_mat @ x
    if transposed:
        x = x.T
    return x.astype(g.dtype)


class Muon:
    # Muon applies SGD-momentum to matrix gradients, then orthogonalizes the result before the
    # parameter update.
    def __init__(self, keys: list[str], params: dict[str, mx.array], args: Hyperparameters):
        self.keys = keys
        self.args = args
        self.buffers = {k: mx.zeros_like(params[k]) for k in keys}

    def step(self, params: dict[str, mx.array], grads: dict[str, mx.array], step: int, lr_mul: float) -> dict[str, mx.array]:
        # Momentum warmup is handled inside Muon rather than by the outer runner
        # because it is specific to this optimizer family. Embedding/scalar Adam
        # groups do not share the same notion of warmup here.
        if self.args.muon_momentum_warmup_steps:
            t = min(step / self.args.muon_momentum_warmup_steps, 1.0)
            momentum = (1.0 - t) * self.args.muon_momentum_warmup_start + t * self.args.muon_momentum
        else:
            momentum = self.args.muon_momentum
        lr = self.args.matrix_lr * lr_mul
        out: dict[str, mx.array] = {}
        for k in self.keys:
            p = params[k]
            g = grads[k]
            # Only matrix-shaped parameters come through Muon. The baseline treats
            # them as the part of the model that most benefits from momentum +
            # orthogonalized updates, while smaller control tensors are left on
            # simpler Adam dynamics. It works well in practice, though the string-
            # and-shape-based partitioning is an obvious candidate for cleanup.
            buf = momentum * self.buffers[k] + g
            self.buffers[k] = buf
            g_eff = g + momentum * buf
            g_ortho = zeropower_newtonschulz5(g_eff, self.args.muon_backend_steps)
            scale = math.sqrt(max(1.0, float(p.shape[0]) / float(p.shape[1])))
            out[k] = p - lr * (g_ortho * scale).astype(p.dtype)
        return out


class SplitOptimizers:
    # - embeddings: Adam with the tied-embedding LR
    # - block matrices (2D): Muon
    # - block scalars + skip weights: Adam
    # This preserves the high-level optimization behavior even though MLX internals differ.
    def __init__(self, model: GPT, args: Hyperparameters):
        self.args = args
        params = dict(tree_flatten(model.parameters()))
        self.embed_key = "tok_emb.weight"
        # Parameter grouping is intentionally explicit and local: we inspect the
        # flattened model state once, then derive the three optimizer groups from
        # tensor names and ranks. That keeps the training script compact, but it
        # also means the optimizer knows a fair amount about model naming.
        # Possible improvement: let model parameters carry semantic tags so the
        # optimizer partition does not depend on substring matching.
        self.matrix_keys = [
            k
            for k, p in params.items()
            if k.startswith("blocks.") and p.ndim == 2 and not any(pattern in k for pattern in CONTROL_TENSOR_NAME_PATTERNS)
        ]
        self.scalar_keys = [
            k
            for k, p in params.items()
            if k == "skip_weights" or (k.startswith("blocks.") and (p.ndim < 2 or any(pattern in k for pattern in CONTROL_TENSOR_NAME_PATTERNS)))
        ]

        self.muon = Muon(self.matrix_keys, params, args)
        self.adam_embed = optim.Adam(
            learning_rate=args.tied_embed_lr,
            betas=[args.beta1, args.beta2],
            eps=args.adam_eps,
            bias_correction=True,
        )
        self.adam_scalar = optim.Adam(
            learning_rate=args.scalar_lr,
            betas=[args.beta1, args.beta2],
            eps=args.adam_eps,
            bias_correction=True,
        )

    def step(self, model: GPT, grads_tree: dict, step: int, lr_mul: float) -> None:
        params = dict(tree_flatten(model.parameters()))
        grads = dict(tree_flatten(grads_tree))
        updated = dict(params)

        # Each optimizer group returns updated tensors into the same flat mapping,
        # and only after all groups have written their slice do we rebuild the
        # nested state tree for `model.update`. This centralizes the state merge
        # and makes it obvious which optimizer owns which parameters.
        updated.update(self.muon.step(params, grads, step=step, lr_mul=lr_mul))

        self.adam_embed.learning_rate = self.args.tied_embed_lr * lr_mul
        updated.update(
            self.adam_embed.apply_gradients(
                {self.embed_key: grads[self.embed_key]},
                {self.embed_key: params[self.embed_key]},
            )
        )

        self.adam_scalar.learning_rate = self.args.scalar_lr * lr_mul
        scalar_grads = {k: grads[k] for k in self.scalar_keys}
        scalar_params = {k: params[k] for k in self.scalar_keys}
        updated.update(self.adam_scalar.apply_gradients(scalar_grads, scalar_params))

        model.update(tree_unflatten(list(updated.items())))


def _np_float32(arr: mx.array) -> np.ndarray:
    # NumPy is used here as a dependable host-side reduction path for clip-norm
    # computation. MLX could in principle do this too, but the extra conversion
    # cost is minor compared to the clarity and numerical predictability of
    # accumulating the norm in float64 on the CPU.
    return np.array(arr.astype(mx.float32), dtype=np.float32, copy=False)


def clip_grad_tree(grads_tree: dict, max_norm: float) -> dict:
    if max_norm <= 0:
        return grads_tree
    flat = dict(tree_flatten(grads_tree))
    # We compute the global norm in host NumPy rather than piecing it together
    # from per-group optimizer internals. That keeps clipping orthogonal to the
    # optimizer split, at the cost of a bit of extra host/device traffic. If
    # clipping becomes performance-sensitive, this is a reasonable place to
    # revisit with a more MLX-native reduction.
    total_sq = 0.0
    for grad in flat.values():
        total_sq += float(np.sum(np.square(_np_float32(grad)), dtype=np.float64))
    if total_sq <= 0.0:
        return grads_tree
    total_norm = math.sqrt(total_sq)
    if total_norm <= max_norm:
        return grads_tree
    scale = max_norm / (total_norm + 1e-12)
    return tree_unflatten([(k, g * scale) for k, g in flat.items()])
