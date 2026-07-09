"""NTK and churn plasticity metrics for PPO agents.

The PPO network ``apply_fn`` has the signature::

    hidden, pi, value = apply_fn(params, hidden, obs)

where ``obs`` is the 6-tuple
``(image, action_encoded, last_reward, sine, cosine, reward_trace)`` (each with
a leading batch axis), ``pi`` is a ``distrax.Categorical`` over ``action_dim``
actions, and ``value`` has shape ``(batch,)``.

Two heads are measured separately:

* **value (critic)** -- scalar value output, the direct analogue of the DQN
  Q-value metrics.
* **policy (actor)** -- the ``action_dim`` policy logits.

For each head we report the NTK Gram-matrix discrete (hard) rank and effective
(stable) rank, plus the per-update *churn* -- the change in the head's
predictions on a fixed reference batch from immediately before to immediately
after one PPO update.  (We do not report the Gram's condition number: on the
small reference-batch Gram its value is dominated by the near-zero end of the
spectrum sitting right at the hard-rank cutoff tolerance, so it swings with
numerical noise rather than tracking anything the effective rank doesn't
already capture more stably.)  The two heads use the churn measure appropriate
to their output, matching C-CHAIN's PPO churn definitions:

* **value (critic)** -- *scale-invariant MSE* churn ``mean((v_after -
  v_before)^2) / (mean(v_before^2) + eps)``.  The numerator is C-CHAIN's value
  churn (``(Δv).pow(2).mean()``); dividing by the value-output power makes it
  invariant to the absolute scale of the value output (which drifts across tasks
  in the non-stationary setting), so the trend reflects how much the value
  function *moved*, not how large its outputs happen to be.
* **policy (actor)** -- the mean *KL divergence*
  ``KL(pi_before || pi_after)`` of the action distribution.  Operating on the
  distribution rather than the raw logits makes it invariant to the softmax
  logit gauge: logit shifts/rescalings that leave the policy unchanged
  contribute zero churn.

We additionally report the *weight update norm* ``||theta_after -
theta_before||`` -- a per-update "is the network still moving" signal,
distinct from the weight *norm* (its magnitude) and weight *drift* (cumulative
distance from init).  Like weight drift, the update norm and the norm are each
split by actor / critic trunk (plus a global total) since the two trunks share
no weights and are trained by different objectives.

The Gram is built in row-chunks (see ``_gram_chunked``) so peak memory is bounded
by the chunk size rather than the reference-set size.
"""

from typing import Any, Callable, Tuple

import jax
import jax.numpy as jnp


def build_ref_obs_tuple(x: jnp.ndarray, action_dim: int, reward_dim: int) -> Tuple:
    """Build the 6-tuple obs the PPO network expects for a single reference obs.

    Scalar / context features (action encoding, last reward, sinusoidal time
    encoding, reward trace) are zeroed, mirroring the DQN reference-metric setup
    in ``utils.metrics.compute_ntk_metrics`` which feeds zero scalars.  A leading
    batch axis of size 1 is added so the convolutional / dense layers see the
    rank they expect.

    Args:
        x: A single reference observation image (no batch axis).
        action_dim: Number of discrete actions (size of the action encoding).
        reward_dim: Width of the ``last_reward`` feature (1 for plain envs,
            ``1 + hint_dim`` for hint envs).

    Returns:
        The 6-tuple ``(image, action_encoded, last_reward, sine, cosine,
        reward_trace)``, each with a leading batch axis of size 1.
    """
    image = jnp.expand_dims(x, 0)
    action_encoded = jnp.zeros((1, action_dim))
    last_reward = jnp.zeros((1, reward_dim))
    sine = jnp.zeros((1, 1))
    cosine = jnp.zeros((1, 1))
    reward_trace = jnp.zeros((1, 1))
    return (image, action_encoded, last_reward, sine, cosine, reward_trace)


def _flatten_jacobian(jac_tree: Any, n_rows: int) -> jnp.ndarray:
    """Flatten a Jacobian pytree to a dense ``[n_rows, n_params]`` matrix."""
    leaves = jax.tree_util.tree_leaves(jac_tree)
    flat_leaves = [leaf.reshape(n_rows, -1) for leaf in leaves]
    return jnp.concatenate(flat_leaves, axis=1)


def _split_pi_vf_total(
    sq_leaves: list, lbl_leaves: list
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """Reduce per-leaf squared-L2 values into (pi, vf, total) L2 norms.

    Shared by ``weight_norm``, ``weight_drift`` and ``weight_update_norm``,
    which all differ only in what per-leaf squared quantity they feed in.
    """
    pi_sq = sum((s for s, l in zip(sq_leaves, lbl_leaves) if l == "pi"), 0.0)
    vf_sq = sum((s for s, l in zip(sq_leaves, lbl_leaves) if l == "vf"), 0.0)
    total_sq = sum(sq_leaves, 0.0)
    return jnp.sqrt(pi_sq), jnp.sqrt(vf_sq), jnp.sqrt(total_sq)


def weight_norm(
    params: Any, labels: Any
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """L2 norm ``||theta||`` of the current params, split by actor / critic trunk.

    The actor and critic trunks share no weights and are trained by different
    objectives, so (as with ``weight_drift``) the norm is reported split by
    trunk plus a global total over every leaf.

    Args:
        params: Current parameters.
        labels: Per-leaf label tree ("pi" / "vf" / ...), same structure
            as params.

    Returns:
        (norm_pi, norm_vf, norm_total) as scalar arrays.
    """
    leaves = jax.tree_util.tree_leaves(params)
    lbl_leaves = jax.tree_util.tree_leaves(labels)
    sq_leaves = [jnp.sum(jnp.square(leaf)) for leaf in leaves]
    return _split_pi_vf_total(sq_leaves, lbl_leaves)


def nan_weight_norm() -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """The ``NaN`` weight-norm triple emitted on non-metric / disabled updates."""
    nan = jnp.float32(jnp.nan)
    return nan, nan, nan


def weight_drift(
    params: Any, init_params: Any, labels: Any
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """L2 distance ``||theta - theta_0||`` between current and initial params.

    The drift is reported split by the actor and critic
    trunks -- which in this RTU-PPO architecture share no weights and are trained
    by different objectives -- plus a global total over every leaf.

    Args:
        params: Current (post-update) parameters.
        init_params: The frozen theta_0 snapshot taken right after init.
        labels: Per-leaf label tree ("pi" / "vf" / ...), same structure
            as params.

    Returns:
        (drift_pi, drift_vf, drift_total) as scalar arrays.
    """
    sqdiff = jax.tree_util.tree_map(
        lambda p, p0: jnp.sum(jnp.square(p - p0)), params, init_params
    )
    sq_leaves = jax.tree_util.tree_leaves(sqdiff)
    lbl_leaves = jax.tree_util.tree_leaves(labels)
    return _split_pi_vf_total(sq_leaves, lbl_leaves)


def nan_weight_drift() -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """The ``NaN`` weight-drift triple emitted on non-metric / disabled updates."""
    nan = jnp.float32(jnp.nan)
    return nan, nan, nan


def weight_update_norm(
    params_before: Any, params_after: Any, labels: Any
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """Per-update L2 norm ``||theta_after - theta_before||``, split by trunk.

    A per-update "is the network still moving" signal, distinct from the
    weight *norm* (its magnitude) and weight *drift* (cumulative distance from
    init).  Split by actor / critic trunk plus a global total, for the same
    reason as ``weight_drift``.

    Args:
        params_before: Parameters before the current PPO update.
        params_after: Parameters after the current PPO update.
        labels: Per-leaf label tree ("pi" / "vf" / ...), same structure
            as params.

    Returns:
        (update_norm_pi, update_norm_vf, update_norm_total) as scalar arrays.
    """
    leaves_before = jax.tree_util.tree_leaves(params_before)
    leaves_after = jax.tree_util.tree_leaves(params_after)
    lbl_leaves = jax.tree_util.tree_leaves(labels)
    sq_leaves = [
        jnp.sum(jnp.square(a - b)) for a, b in zip(leaves_after, leaves_before)
    ]
    return _split_pi_vf_total(sq_leaves, lbl_leaves)


def _gram_chunked(
    f_single: Callable, params: Any, x_ref: jnp.ndarray, chunk: int, m: int
) -> jnp.ndarray:
    """NTK Gram matrix ``J Jᵀ`` built in row-chunks, never materializing ``J``.

    ``f_single(params, x)`` maps one reference obs to an ``m``-vector head output
    (``m = 1`` for the scalar value head, ``m = action_dim`` for the policy
    logits).  The full Jacobian ``J`` therefore has ``n_ref * m`` rows and one
    column per parameter -- the object whose ``[n_ref*m, n_params]`` size causes
    the OOM when formed all at once.

    Instead we tile the reference set into chunks of ``chunk`` samples and
    compute the Gram blockwise: for each pair of chunks ``(i, j)`` we materialize
    only the two chunk-Jacobians ``J_i, J_j`` (shape ``[chunk*m, n_params]``) and
    their product ``J_i J_jᵀ``.  Peak memory is ``O(chunk * m * n_params +
    (n_ref*m)²)`` -- bounded by ``chunk`` rather than ``n_ref`` -- at the cost of
    recomputing each chunk-Jacobian ``n_chunks`` times.  The result is bit-for-bit
    the dense ``J Jᵀ`` (modulo float reassociation).

    ``chunk`` need not divide ``n_ref``: the reference set is padded up to a whole
    number of chunks and the padded rows are zeroed out of every chunk-Jacobian,
    so they contribute nothing to the Gram (zero rows add only zero eigenvalues,
    leaving rank and effective rank untouched).
    """
    n = x_ref.shape[0]
    chunk = min(chunk, n)
    n_chunks = -(-n // chunk)  # ceil
    pad = n_chunks * chunk - n
    if pad:
        x_pad = jnp.concatenate(
            [x_ref, jnp.zeros((pad, *x_ref.shape[1:]), x_ref.dtype)]
        )
        valid = jnp.concatenate([jnp.ones(n), jnp.zeros(pad)])
    else:
        x_pad, valid = x_ref, jnp.ones(n)
    x_chunks = x_pad.reshape(n_chunks, chunk, *x_ref.shape[1:])
    valid_chunks = valid.reshape(n_chunks, chunk)

    def chunk_jac(xc: jnp.ndarray, vc: jnp.ndarray) -> jnp.ndarray:
        """Flat ``[chunk*m, n_params]`` Jacobian for one chunk, padded rows zeroed."""
        jac = jax.vmap(jax.jacrev(f_single, argnums=0), in_axes=(None, 0))(params, xc)
        flat = _flatten_jacobian(jac, chunk * m)
        row_mask = jnp.repeat(vc, m)  # each sample owns m consecutive rows
        return flat * row_mask[:, None]

    def row_of_blocks(carry_i):
        xi, vi = carry_i
        jac_i = chunk_jac(xi, vi)  # [chunk*m, n_params]

        def block(carry_j):
            xj, vj = carry_j
            jac_j = chunk_jac(xj, vj)
            return jac_i @ jac_j.T  # [chunk*m, chunk*m]

        return jax.lax.map(block, (x_chunks, valid_chunks))  # [n_chunks, cm, cm]

    blocks = jax.lax.map(row_of_blocks, (x_chunks, valid_chunks))
    # blocks[i, j] is the (i, j) Gram block -> reorder to a dense [n_rows, n_rows].
    cm = chunk * m
    n_rows = n_chunks * cm
    return blocks.transpose(0, 2, 1, 3).reshape(n_rows, n_rows)


def _ntk_rank_eff(ntk: jnp.ndarray) -> Tuple[jnp.ndarray, jnp.ndarray]:
    """Discrete (hard) NTK rank and effective (stable) rank from the Gram matrix.

    ``ntk = J Jᵀ`` is symmetric positive-semidefinite, so a single symmetric
    eigendecomposition (``eigvalsh``) gives every spectral quantity we need --
    cheaper and more numerically appropriate than the SVD the old
    ``matrix_rank`` path used.

    * **hard rank** -- count of eigenvalues above ``λ_max * n_rows * eps``, the
      same tolerance ``jnp.linalg.matrix_rank`` applies to the Gram, so this
      matches the previously logged rank semantics exactly.
    * **effective rank** -- the *stable rank* ``(Σλ) / λ_max = ‖J‖_F² / ‖J‖₂²``,
      a smooth, threshold-free measure of how many directions actually carry
      energy.  It equals the hard rank only for a perfectly flat spectrum and is
      otherwise smaller; the gap reveals spectral concentration that the integer
      rank cannot.

    We do not report the condition number ``λ_max / λ_min``: on this small
    reference-batch Gram, ``λ_min`` sits right at the hard-rank cutoff
    tolerance by construction, so the ratio is dominated by numerical noise at
    the truncation boundary rather than tracking anything beyond what the
    effective rank already captures more stably.
    """
    eigvals = jnp.clip(jnp.linalg.eigvalsh(ntk), a_min=0.0)  # ascending, PSD
    lam_max = eigvals[-1]
    n_rows = ntk.shape[0]
    tol = lam_max * n_rows * jnp.finfo(ntk.dtype).eps
    rank = jnp.sum(eigvals > tol).astype(jnp.float32)
    eff_rank = jnp.where(lam_max > 0, jnp.sum(eigvals) / lam_max, 0.0).astype(
        jnp.float32
    )
    return rank, eff_rank


def value_metrics(
    apply_fn: Callable,
    params_before: Any,
    params_after: Any,
    init_hstate: Any,
    x_ref: jnp.ndarray,
    action_dim: int,
    reward_dim: int,
    chunk: int,
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """NTK rank / effective rank and per-update churn for the value head.

    NTK is measured on the post-update parameters (the network's current state,
    matching the DQN convention).  Churn is the *scale-invariant MSE* of the
    value change on ``x_ref`` from ``params_before`` to ``params_after``:
    ``mean((v_after - v_before)^2) / (mean(v_before^2) + eps)`` -- C-CHAIN's
    ``(Δv).pow(2).mean()`` value churn normalized by the value-output power, which
    removes the absolute value-output scale (it drifts across tasks) so the trend
    reflects how much the value function moved.  ``chunk`` is the row-chunk size
    for the memory-bounded Gram build; it changes only peak memory / speed, not
    the result.

    Returns:
        ``(rank, eff_rank, churn)`` as scalar arrays.
    """

    def value_of(params, x):
        obs = build_ref_obs_tuple(x, action_dim, reward_dim)
        _, _, value = apply_fn(params, init_hstate, obs)
        return value[0:1]  # (1,) so the Gram builder sees a uniform m-vector head

    # Per-sample value predictions before / after the update.
    pred_before = jax.vmap(value_of, in_axes=(None, 0))(params_before, x_ref)
    pred_after = jax.vmap(value_of, in_axes=(None, 0))(params_after, x_ref)

    # NTK on the current (post-update) params; Gram built in row-chunks.
    ntk = _gram_chunked(value_of, params_after, x_ref, chunk, m=1)
    rank, eff_rank = _ntk_rank_eff(ntk)

    # Scale-invariant MSE churn: C-CHAIN's value churn ``mean((v_after -
    # v_before)^2)`` normalized by the value-output power ``mean(v_before^2)``.
    # Numerator and denominator share units (value^2), so the ratio is
    # dimensionless and invariant under rescaling of the value output (v -> a*v).
    eps = 1e-8
    mse = jnp.mean(jnp.square(pred_after - pred_before))
    scale = jnp.mean(jnp.square(pred_before))
    churn = mse / (scale + eps)

    return rank, eff_rank, churn


def policy_metrics(
    apply_fn: Callable,
    params_before: Any,
    params_after: Any,
    init_hstate: Any,
    x_ref: jnp.ndarray,
    action_dim: int,
    reward_dim: int,
    chunk: int,
) -> Tuple[jnp.ndarray, jnp.ndarray, jnp.ndarray]:
    """NTK rank / effective rank and per-update churn for the policy head.

    The policy output is the ``action_dim`` logit vector, so the Jacobian has
    ``n_ref * action_dim`` rows (and the rank ceiling is correspondingly
    ``action_dim`` times the value head's).  Churn is the mean KL divergence
    ``KL(pi_before || pi_after)`` of the action distribution on ``x_ref`` over one
    update -- the distributional measure C-CHAIN uses for the actor.  Operating on
    the distribution rather than the logits makes it invariant to the softmax
    logit gauge.  ``chunk`` is the row-chunk size for the memory-bounded Gram
    build; it changes only peak memory / speed, not the result.

    Returns:
        ``(rank, eff_rank, churn)`` as scalar arrays.
    """

    def logits_of(params, x):
        obs = build_ref_obs_tuple(x, action_dim, reward_dim)
        _, pi, _ = apply_fn(params, init_hstate, obs)
        return pi.logits[0]  # (action_dim,)

    def probs_of(params, x):
        obs = build_ref_obs_tuple(x, action_dim, reward_dim)
        _, pi, _ = apply_fn(params, init_hstate, obs)
        return pi.probs[0]  # (action_dim,)

    p_before = jax.vmap(probs_of, in_axes=(None, 0))(params_before, x_ref)
    p_after = jax.vmap(probs_of, in_axes=(None, 0))(params_after, x_ref)

    # NTK on the current (post-update) params; Gram built in row-chunks, each
    # sample contributing action_dim rows.
    ntk = _gram_chunked(logits_of, params_after, x_ref, chunk, m=action_dim)
    rank, eff_rank = _ntk_rank_eff(ntk)

    # Mean KL(p_before || p_after) over the reference batch.  eps keeps the logs
    # finite for zero-probability actions.
    eps = 1e-8
    kl = jnp.sum(
        p_before * (jnp.log(p_before + eps) - jnp.log(p_after + eps)), axis=-1
    )
    churn = jnp.mean(kl)

    return rank, eff_rank, churn


def compute_ppo_metrics(
    apply_fn: Callable,
    params_before: Any,
    params_after: Any,
    init_hstate: Any,
    x_ref: jnp.ndarray,
    action_dim: int,
    reward_dim: int,
    chunk: int,
    labels: Any,
    compute_value: bool = True,
    compute_policy: bool = True,
) -> Tuple[jnp.ndarray, ...]:
    """Compute value- and policy-head NTK + churn metrics, and the weight update norm.

    Pure JAX and statically shaped so it can be traced inside ``jax.lax.scan``
    / ``jax.lax.cond`` and vmapped across runs.  Heads that are disabled (or
    when this is called on a non-metric step via ``lax.cond``) report ``NaN``.

    The weight norm is intentionally *not* computed here -- it has its own
    cadence and config flag; see ``weight_norm`` / ``nan_weight_norm``.

    Args:
        apply_fn: The network ``apply`` function.
        params_before: Parameters before the current PPO update (for churn and
            the weight update norm).
        params_after: Parameters after the current PPO update (NTK + churn +
            weight update norm).
        init_hstate: Initial hidden state sized for batch 1 (zeros for RTUs).
        x_ref: Reference observation images, shape ``[n_ref, ...]``.
        action_dim: Number of discrete actions.
        reward_dim: Width of the ``last_reward`` feature.
        chunk: Row-chunk size for the memory-bounded Gram build (result-invariant).
        labels: Per-leaf label tree ("pi" / "vf" / ...), same structure as
            ``params_before`` / ``params_after``, for splitting the weight
            update norm by actor / critic trunk.
        compute_value: Whether to measure the value head.
        compute_policy: Whether to measure the policy head.

    Returns:
        ``(value_rank, value_eff_rank, value_churn, policy_rank,
        policy_eff_rank, policy_churn, weight_update_norm_pi,
        weight_update_norm_vf, weight_update_norm_total)`` as scalar arrays.
    """
    nan = jnp.float32(jnp.nan)

    if compute_value:
        v_rank, v_eff_rank, v_churn = value_metrics(
            apply_fn,
            params_before,
            params_after,
            init_hstate,
            x_ref,
            action_dim,
            reward_dim,
            chunk,
        )
    else:
        v_rank, v_eff_rank, v_churn = nan, nan, nan

    if compute_policy:
        p_rank, p_eff_rank, p_churn = policy_metrics(
            apply_fn,
            params_before,
            params_after,
            init_hstate,
            x_ref,
            action_dim,
            reward_dim,
            chunk,
        )
    else:
        p_rank, p_eff_rank, p_churn = nan, nan, nan

    wun_pi, wun_vf, wun_total = weight_update_norm(params_before, params_after, labels)

    return (
        v_rank,
        v_eff_rank,
        v_churn,
        p_rank,
        p_eff_rank,
        p_churn,
        wun_pi,
        wun_vf,
        wun_total,
    )


def nan_ppo_metrics() -> Tuple[jnp.ndarray, ...]:
    """The all-``NaN`` NTK / churn / weight-update-norm tuple emitted on
    non-metric updates."""
    nan = jnp.float32(jnp.nan)
    return nan, nan, nan, nan, nan, nan, nan, nan, nan
