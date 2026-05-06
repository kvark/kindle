//! Policy and Value Head.
//!
//! - **Policy** `π(z_t) → action distribution`, updated by credit-weighted
//!   policy gradient with entropy bonus.
//! - **Value Head** `V(z_t) → V̂`, trained via TD using the credit-adjusted
//!   reward signal, serving as a variance-reduction baseline.

use meganeura::graph::{Graph, NodeId};
use meganeura::nn;

/// `scale · tanh(x / scale)`: an element-wise soft clamp that saturates
/// smoothly to ±scale. Implemented via full-shape constant tensors
/// because meganeura's `Op::Mul` requires matching shapes (no scalar
/// broadcast).
fn scaled_tanh(g: &mut Graph, x: NodeId, scale: f32, batch_size: usize, last_dim: usize) -> NodeId {
    let n = batch_size * last_dim;
    let scale_full = g.constant(vec![scale; n], &[batch_size, last_dim]);
    let inv_scale_full = g.constant(vec![1.0 / scale; n], &[batch_size, last_dim]);
    let shrunk = g.mul(x, inv_scale_full);
    let squashed = g.tanh(shrunk);
    g.mul(squashed, scale_full)
}

/// Stochastic policy network for discrete action spaces.
pub struct Policy {
    pub fc1: nn::Linear,
    pub fc2: nn::Linear,
}

impl Policy {
    pub fn new(g: &mut Graph, latent_dim: usize, action_dim: usize, hidden_dim: usize) -> Self {
        Self {
            fc1: nn::Linear::new(g, "policy.fc1", latent_dim, hidden_dim),
            fc2: nn::Linear::no_bias(g, "policy.fc2", hidden_dim, action_dim),
        }
    }

    /// Forward pass: `[batch, latent_dim] → [batch, action_dim]` (logits).
    pub fn forward(&self, g: &mut Graph, z: NodeId) -> NodeId {
        let h = self.fc1.forward(g, z);
        let h = g.relu(h);
        self.fc2.forward(g, h)
    }
}

/// Phase G Tier-3: per-option fc2 heads. The shared trunk (fc1) still
/// produces a state-conditioned hidden vector `h`, but each option gets
/// its *own* `[hidden_dim → action_dim]` linear head. The active option's
/// head is selected per-lane via a onehot-weighted sum, so only that
/// head sees gradient on a given step — capacity is silo'd per option.
///
/// Without broadcast-mul or gather, the selection is spelled out as:
///   col_o    = onehot @ e_o           (e_o ∈ R^{N×1}, 1 at row o)
///   mask_o   = col_o @ ones_row       (ones_row ∈ R^{1×A})
///   masked_o = logits_o * mask_o
///   combined = Σ_o masked_o
fn per_option_fc2(
    g: &mut Graph,
    h: NodeId,
    option_onehot: NodeId,
    num_options: usize,
    hidden_dim: usize,
    action_dim: usize,
) -> NodeId {
    let ones_row = g.constant(vec![1.0f32; action_dim], &[1, action_dim]);
    let mut sum: Option<NodeId> = None;
    for o in 0..num_options {
        let head_o = nn::Linear::new(g, &format!("policy.fc2_opt{o}"), hidden_dim, action_dim);
        let logits_o = head_o.forward(g, h);

        let mut selector = vec![0.0f32; num_options];
        selector[o] = 1.0;
        let sel_col = g.constant(selector, &[num_options, 1]);
        let col_o = g.matmul(option_onehot, sel_col);
        let mask_full = g.matmul(col_o, ones_row);

        let masked_o = g.mul(logits_o, mask_full);
        sum = Some(match sum {
            None => masked_o,
            Some(prev) => g.add(prev, masked_o),
        });
    }
    sum.expect("num_options >= 1")
}

/// Value head: estimates cumulative future reward from the current state.
pub struct ValueHead {
    pub fc1: nn::Linear,
    pub fc2: nn::Linear,
}

impl ValueHead {
    pub fn new(g: &mut Graph, latent_dim: usize, hidden_dim: usize) -> Self {
        Self {
            fc1: nn::Linear::new(g, "value.fc1", latent_dim, hidden_dim),
            fc2: nn::Linear::no_bias(g, "value.fc2", hidden_dim, 1),
        }
    }

    /// Forward pass: `[batch, latent_dim] → [batch, 1]`.
    pub fn forward(&self, g: &mut Graph, z: NodeId) -> NodeId {
        let h = self.fc1.forward(g, z);
        let h = g.relu(h);
        self.fc2.forward(g, h)
    }
}

/// Build the discrete policy + value training graph.
///
/// Inputs:
/// - `"z"`: `[batch_size, latent_dim]` — latent from encoder (detached, fed as input)
/// - `"action"`: `[batch_size, action_dim]` — one-hot taken action (or
///   advantage-weighted one-hot for REINFORCE-style per-row weighting, see
///   `agent.rs::policy_step_batched`).
/// - `"value_target"`: `[batch_size, 1]` — TD target for value head
///
/// Outputs:
/// - `[0]`: combined loss (policy cross-entropy + value MSE, optionally
///   minus `entropy_beta · H(π)`; mean over batch)
/// - `[1]`: logits `[batch_size, action_dim]` — for action sampling
/// - `[2]`: value `[batch_size, 1]` — for advantage computation
///
/// `entropy_beta` controls a shannon-entropy regularizer on the policy:
///
///   H(π) = -∑_k softmax(ℓ)_k · log softmax(ℓ)_k
///
/// The loss subtracts `entropy_beta · H(π)` (after mean-reduction across
/// the batch and action dims). For `β > 0` this *encourages* higher
/// entropy — the standard exploration bonus in policy-gradient methods.
/// For `β < 0` it *discourages* entropy and drives the softmax to
/// collapse toward a delta distribution (useful when a policy is stuck
/// at uniform and needs to commit). At `β = 0` the entropy term is
/// elided entirely and the graph is identical to the pre-regularization
/// policy graph — parity guarantee.
pub fn build_policy_graph(
    latent_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    batch_size: usize,
    entropy_beta: f32,
    num_options: usize,
    per_option_heads: bool,
    value_loss_coef: f32,
    value_clip_scale: f32,
) -> Graph {
    let mut g = Graph::new();
    let z = g.input("z", &[batch_size, latent_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    let value_target = g.input("value_target", &[batch_size, 1]);

    // Phase G v2: per-option direct-to-logits bias head. Each option
    // has its own learned `[action_dim]` bias vector; the bias is
    // selected per-lane by matmul with a one-hot option encoding.
    // This bypasses the shared trunk so the option-conditional signal
    // is not attenuated by Xavier-init trunk weights or crowded out
    // by the base-reward gradient through z.
    //
    // Phase G Tier-3: when `per_option_heads` is set, the shared fc2
    // is replaced by N per-option fc2 heads, giving each option its
    // own `[hidden_dim → action_dim]` matrix — the bias subsumes into
    // each head's own bias so we drop the separate option_bias layer.
    let raw_logits = if num_options > 1 && per_option_heads {
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let fc1 = nn::Linear::new(&mut g, "policy.fc1", latent_dim, hidden_dim);
        let h = fc1.forward(&mut g, z);
        let h = g.relu(h);
        per_option_fc2(
            &mut g,
            h,
            option_onehot,
            num_options,
            hidden_dim,
            action_dim,
        )
    } else if num_options > 1 {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        let trunk_logits = policy.forward(&mut g, z);
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let option_bias =
            nn::Linear::no_bias(&mut g, "policy.option_bias", num_options, action_dim);
        let bias_out = option_bias.forward(&mut g, option_onehot);
        g.add(trunk_logits, bias_out)
    } else {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        policy.forward(&mut g, z)
    };

    // No soft-clamp on the logits themselves — a tanh bound here
    // saturates the gradient as the policy commits and prevents
    // useful confident policies from forming (Taxi: entropy 0.20 →
    // 1.78 under a scale=50 clamp). The value head's MSE was the
    // dominant long-run overflow source; clamping value output alone
    // (below) is sufficient to keep policy-loss finite over 1M-step
    // runs.
    let logits = raw_logits;

    // Value head conditions on z only — option-agnostic baseline so
    // `advantage = reward − value` retains the option-conditional
    // bonus signal instead of seeing it cancelled. A symmetric tanh
    // soft-clamp keeps the value output bounded in ±100 so MSE can't
    // drive the head into an overflow loop.
    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);

    // Policy loss: cross-entropy with one-hot action selects -log π(a|s)
    let policy_loss = g.cross_entropy_loss(logits, action);
    let value_loss_raw = g.mse_loss(value, value_target);
    // Value-loss coefficient (PPO/A2C `vf_coef`). Under a shared
    // optimizer the value head tends to dominate the combined
    // gradient — its MSE target is reward-scale while the policy-CE
    // loss is O(log K) — so we weight value down explicitly. Default
    // 1.0 keeps the old behavior.
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let base_loss = g.add(policy_loss, value_loss);

    // Entropy regularizer: subtract β · H(π) from the loss.
    //
    //   mean_all(p · log p) = -<H>/K   (negative scalar, K = action_dim)
    //
    // so `loss += β · mean_all(p · log p)` adds a negative term for β > 0
    // (encouraging entropy, since minimizing a more-negative value lets
    // |H| grow) and a positive term for β < 0. Elide entirely at β = 0 so
    // we don't add a no-op `softmax→log_softmax→mul→mean→scalar→mul→add`
    // chain that the optimizer would then have to prove away.
    let total_loss = if entropy_beta == 0.0 {
        base_loss
    } else {
        // Entropy regularizer using the fused `log_softmax` — numerically
        // stable (uses `ℓ − log_sum_exp(ℓ)` internally, no log-of-zero) and
        // with a proper backward kernel as of meganeura commit 7c3bdcf.
        let sm = g.softmax(logits);
        let lsm = g.log_softmax(logits);
        let p_log_p = g.mul(sm, lsm);
        let mean_ent = g.mean_all(p_log_p);
        let beta_node = g.scalar(entropy_beta);
        let ent_penalty = g.mul(mean_ent, beta_node);
        g.add(base_loss, ent_penalty)
    };

    g.set_outputs(vec![total_loss, logits, value]);
    g
}

/// Build the discrete PPO-style policy + value training graph.
///
/// Inputs:
/// - `"z"`: `[batch_size, latent_dim]`
/// - `"action"`: `[batch_size, action_dim]` — one-hot of the taken action
///   (MUST sum to 1 per row — plain one-hot, no advantage weighting)
/// - `"advantage"`: `[batch_size, 1]` — per-row scalar advantage Â_t
/// - `"old_prob_taken"`: `[batch_size, 1]` — π_old(a_t|s_t), the probability
///   of the taken action under the policy that collected the data (positive,
///   non-zero)
/// - `"value_target"`: `[batch_size, 1]` — TD target for the value head
///
/// Outputs: `[loss, logits, value]`.
///
/// Loss: the PPO clipped surrogate
/// ```text
/// r_t = π_new(a_t|s_t) / π_old(a_t|s_t)
/// L = -E[ min(r_t · Â_t, clip(r_t, 1-ε, 1+ε) · Â_t) ]
/// ```
/// Decomposed using only the ops meganeura has today: softmax (→prob),
/// per-row gather via matmul with a `[K,1]` ones column, elementwise
/// division, and `greater()`-gated min/max selectors. The `greater` op
/// has zero backward gradient, so the clip boundary correctly produces
/// zero gradient — the defining property that makes PPO a proper trust
/// region and stops committed policies from overshooting.
///
/// `entropy_beta` and `value_loss_coef` behave identically to the
/// non-PPO variant.
pub fn build_ppo_policy_graph(
    latent_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    batch_size: usize,
    clip_eps: f32,
    value_loss_coef: f32,
    entropy_beta: f32,
    value_clip_scale: f32,
    z_layer_norm: bool,
    z_layer_norm_scale: f32,
) -> Graph {
    let mut g = Graph::new();
    let z_raw = g.input("z", &[batch_size, latent_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    let advantage = g.input("advantage", &[batch_size, 1]);
    let old_prob_taken = g.input("old_prob_taken", &[batch_size, 1]);
    let value_target = g.input("value_target", &[batch_size, 1]);

    // Optional LayerNorm on z before policy/value heads. The encoder
    // under multi-game training places per-game centroids ~15× farther
    // apart than within-game state variation; without normalization the
    // policy gradient is dominated by the between-game offset and
    // can't learn state-conditioned behavior. LayerNorm zero-means
    // and unit-stds each row, equalizing per-dim amplitudes so
    // within-game state info competes with between-game offset on
    // even footing. (Diagnosed 2026-05-05.)
    //
    // Vanilla LayerNorm shrank z magnitude from ~40 to ~1, which
    // killed the policy's ability to produce committed logits under
    // PPO clip + entropy_beta (verified 2026-05-06). The
    // `z_layer_norm_scale` constant scales the LN output to recover
    // signal magnitude while preserving per-dim equalization;
    // applied as a constant multiplier (not learnable) so the scale
    // stays predictable across training.
    let z = if z_layer_norm {
        let ln = nn::LayerNorm::new(&mut g, "policy.z_ln", latent_dim, 1e-5);
        let z_normed = ln.forward(&mut g, z_raw);
        if (z_layer_norm_scale - 1.0).abs() < 1e-6 {
            z_normed
        } else {
            // scalar broadcast: same-shape constant tensor, element-wise mul.
            let s = g.constant(
                vec![z_layer_norm_scale; batch_size * latent_dim],
                &[batch_size, latent_dim],
            );
            g.mul(z_normed, s)
        }
    } else {
        z_raw
    };

    let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
    let logits = policy.forward(&mut g, z);

    // π_new(a | s) — probability of the taken action under the current
    // policy. Built from `softmax(logits) * one_hot` followed by a
    // per-row sum implemented as matmul with a `[K, 1]` ones vector.
    let sm_new = g.softmax(logits);
    let p_per_class = g.mul(sm_new, action);
    let ones_k1 = g.constant(vec![1.0; action_dim], &[action_dim, 1]);
    let new_prob_taken = g.matmul(p_per_class, ones_k1);

    // ratio r_t = π_new / π_old
    let ratio = g.div(new_prob_taken, old_prob_taken);

    // Clip ratio to [1-ε, 1+ε] via two `greater()`-gated selectors:
    // ratio_hi = min(ratio, 1+ε)
    // ratio_clip = max(ratio_hi, 1-ε)
    let one_plus_eps = g.constant(vec![1.0 + clip_eps; batch_size], &[batch_size, 1]);
    let one_minus_eps = g.constant(vec![1.0 - clip_eps; batch_size], &[batch_size, 1]);
    let ones_bx1 = g.constant(vec![1.0; batch_size], &[batch_size, 1]);

    // min(a, b) = (1 - gate) * a + gate * b  where gate = greater(a, b)
    let gate_over = g.greater(ratio, one_plus_eps);
    let neg_gate_over = g.neg(gate_over);
    let inv_gate_over = g.add(ones_bx1, neg_gate_over);
    let term1 = g.mul(ratio, inv_gate_over);
    let term2 = g.mul(one_plus_eps, gate_over);
    let ratio_hi = g.add(term1, term2);

    // max(a, b) = (1 - gate) * a + gate * b  where gate = greater(b, a)
    let gate_under = g.greater(one_minus_eps, ratio_hi);
    let neg_gate_under = g.neg(gate_under);
    let inv_gate_under = g.add(ones_bx1, neg_gate_under);
    let cterm1 = g.mul(ratio_hi, inv_gate_under);
    let cterm2 = g.mul(one_minus_eps, gate_under);
    let ratio_clip = g.add(cterm1, cterm2);

    // surr1 = r_t · Â_t,  surr2 = clip(r_t) · Â_t
    let surr1 = g.mul(ratio, advantage);
    let surr2 = g.mul(ratio_clip, advantage);

    // min(surr1, surr2) → pessimistic of the two (PPO's conservative choice)
    let gate_min = g.greater(surr1, surr2);
    let neg_gate_min = g.neg(gate_min);
    let inv_gate_min = g.add(ones_bx1, neg_gate_min);
    let smin1 = g.mul(surr1, inv_gate_min);
    let smin2 = g.mul(surr2, gate_min);
    let surr_min = g.add(smin1, smin2);

    // Policy loss = -mean(surr_min). We MAXIMIZE surr_min, so loss negates.
    let neg_surr_min = g.neg(surr_min);
    let policy_loss = g.mean_all(neg_surr_min);

    // Value head — same structure as the non-PPO path
    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);
    let value_loss_raw = g.mse_loss(value, value_target);
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let base_loss = g.add(policy_loss, value_loss);

    let total_loss = if entropy_beta == 0.0 {
        base_loss
    } else {
        let sm = g.softmax(logits);
        let lsm = g.log_softmax(logits);
        let p_log_p = g.mul(sm, lsm);
        let mean_ent = g.mean_all(p_log_p);
        let beta_node = g.scalar(entropy_beta);
        let ent_penalty = g.mul(mean_ent, beta_node);
        g.add(base_loss, ent_penalty)
    };

    g.set_outputs(vec![total_loss, logits, value]);
    g
}

/// Build the continuous policy + value training graph for a diagonal
/// Gaussian with fixed unit variance.
///
/// Inputs:
/// - `"z"`: `[batch_size, latent_dim]` — latent from encoder
/// - `"action"`: `[batch_size, action_dim]` — the taken action vector
/// - `"value_target"`: `[batch_size, 1]` — TD target for value head
///
/// Outputs:
/// - `[0]`: combined loss (mean MSE + value MSE, mean over batch)
/// - `[1]`: action mean `[batch_size, action_dim]` — sampled by adding Gaussian noise
/// - `[2]`: value `[batch_size, 1]`
///
/// For a fixed-variance Gaussian, the negative log-likelihood of the taken
/// action is `0.5·(a − μ)² / σ² + const`. With σ² = 1 this reduces to the
/// MSE between predicted mean and taken action, up to a constant — the
/// same advantage-weighted LR trick applies.
/// End-to-end discrete policy graph: encoder + policy + value all in
/// one graph, trained on the combined loss. Owns its own copy of the
/// encoder weights (under `policy_encoder.*` names so they don't
/// collide with the wm_session encoder).
///
/// Inputs:
/// - `"obs"`: `[batch_size, obs_dim]` — raw observation tokens
/// - `"task"`: `[batch_size, task_dim]` — task embedding
/// - `"action"`: `[batch_size, action_dim]` — advantage-weighted one-hot
///   (same shape as `build_policy_graph`)
/// - `"value_target"`: `[batch_size, 1]` — TD target
///
/// Outputs: `[loss, logits, value]` (same indexing as combined graph).
///
/// Why this exists: the standard `build_policy_graph` takes `z` as
/// an input (the encoder output computed elsewhere by `wm_session`).
/// That setup means the policy/value loss gradient stops at z and
/// never reaches the encoder weights. The encoder is then trained
/// only by WM next-state-prediction loss, which produces features
/// optimized for prediction, not for control. Empirically this
/// caps CartPole at +24 (random baseline).
///
/// This e2e variant lets the policy/value gradient flow into a
/// dedicated encoder copy, matching what a standard A2C/PPO
/// implementation does. The wm_session continues to train its own
/// independent encoder copy on the WM loss; the two encoders coexist.
#[allow(clippy::too_many_arguments)]
pub fn build_policy_graph_e2e(
    obs_dim: usize,
    task_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    latent_dim: usize,
    batch_size: usize,
    entropy_beta: f32, // If > 0 at construction, builds entropy branch
    // with a runtime-mutable input "entropy_beta".
    // If == 0, branch is fully elided (parity).
    value_loss_coef: f32,
    value_clip_scale: f32,
    num_options: usize,     // L1 options support: 0/1 = flat, >1 = options
    per_option_heads: bool, // when num_options > 1: per-option fc2 vs shared+bias
    recon_loss_coef: f32,   // > 0 builds a reconstruction decoder head
    // (z → obs') + MSE loss against the obs input.
    // Forces encoder to retain enough info to
    // invert. Anti-collapse signal.
    reward_pred_loss_coef: f32, // > 0 builds a reward-prediction MLP head
                                // (z → r̂) + MSE loss against per-row reward.
                                // Adds input "reward_target". Forces encoder
                                // to retain reward-predictive features.
) -> Graph {
    let mut g = Graph::new();
    let obs = g.input("obs", &[batch_size, obs_dim]);
    let task = g.input("task", &[batch_size, task_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    let value_target = g.input("value_target", &[batch_size, 1]);

    // Dedicated policy-side encoder. Same arch as the WM-side encoder
    // (so an A/B that swaps weights is meaningful), but separate
    // parameter names → independent gradient state.
    let encoder = build_named_encoder(&mut g, obs_dim, task_dim, latent_dim, hidden_dim);
    let z = encoder_forward(&mut g, &encoder, obs, task);

    // Build option-conditional policy if num_options > 1, else flat.
    // The option_onehot input is used twice (logits forward + entropy
    // forward on stop_gradient(z)), but both forwards share the same
    // option choice — i.e., the policy graph is conditioned on the L1
    // option selected by the option_session. Same routing as
    // build_policy_graph: per_option_heads gives full per-option fc2
    // matrices; the cheaper shared-trunk + per-option-bias path is
    // used when per_option_heads=false.
    let (logits, option_onehot) = if num_options > 1 && per_option_heads {
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let fc1 = nn::Linear::new(&mut g, "policy.fc1", latent_dim, hidden_dim);
        let h = fc1.forward(&mut g, z);
        let h = g.relu(h);
        (
            per_option_fc2(
                &mut g,
                h,
                option_onehot,
                num_options,
                hidden_dim,
                action_dim,
            ),
            Some(option_onehot),
        )
    } else if num_options > 1 {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        let trunk_logits = policy.forward(&mut g, z);
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let option_bias =
            nn::Linear::no_bias(&mut g, "policy.option_bias", num_options, action_dim);
        let bias_out = option_bias.forward(&mut g, option_onehot);
        (g.add(trunk_logits, bias_out), Some(option_onehot))
    } else {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        (policy.forward(&mut g, z), None)
    };

    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);

    let policy_loss = g.cross_entropy_loss(logits, action);
    let value_loss_raw = g.mse_loss(value, value_target);
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let base_loss = g.add(policy_loss, value_loss);

    // Reconstruction decoder anti-collapse loss: predict the input obs
    // from z. The MSE target is `stop_gradient(obs)` (the input itself,
    // detached so this loss never tries to learn from changing labels).
    // Forces the encoder to retain enough information about the raw
    // observation that an inverse exists. Standard auto-encoder term.
    let base_loss = if recon_loss_coef > 0.0 {
        let dec_fc1 = nn::Linear::new(&mut g, "recon.fc1", latent_dim, hidden_dim);
        let dec_fc2 = nn::Linear::no_bias(&mut g, "recon.fc2", hidden_dim, obs_dim);
        let dh = dec_fc1.forward(&mut g, z);
        let dh = g.relu(dh);
        let recon = dec_fc2.forward(&mut g, dh);
        let obs_target = g.stop_gradient(obs);
        let recon_loss_raw = g.mse_loss(recon, obs_target);
        let recon_coef = g.scalar(recon_loss_coef);
        let recon_loss = g.mul(recon_loss_raw, recon_coef);
        g.add(base_loss, recon_loss)
    } else {
        base_loss
    };

    // Reward-prediction-from-z anti-collapse loss: predict per-row
    // reward from z via a small MLP. Adds input "reward_target".
    // Forces z to retain reward-predictive features (state components
    // that move the reward — for LunarLander: vy, angle, leg contact).
    // Standard auxiliary task in model-based RL.
    let base_loss = if reward_pred_loss_coef > 0.0 {
        let reward_target = g.input("reward_target", &[batch_size, 1]);
        let r_fc1 = nn::Linear::new(&mut g, "reward_pred.fc1", latent_dim, hidden_dim);
        let r_fc2 = nn::Linear::no_bias(&mut g, "reward_pred.fc2", hidden_dim, 1);
        let rh = r_fc1.forward(&mut g, z);
        let rh = g.relu(rh);
        let r_hat = r_fc2.forward(&mut g, rh);
        let r_target_det = g.stop_gradient(reward_target);
        let r_loss_raw = g.mse_loss(r_hat, r_target_det);
        let r_coef = g.scalar(reward_pred_loss_coef);
        let r_loss = g.mul(r_loss_raw, r_coef);
        g.add(base_loss, r_loss)
    } else {
        base_loss
    };

    // Entropy term: if construction-time beta > 0, include the branch
    // with a runtime-mutable input "entropy_beta" (so the harness can
    // anneal it over training). If beta == 0, fully elide the branch —
    // preserves byte-identical behavior with pre-input-mode runs.
    // Detach z before re-running the policy head on stop_gradient(z) —
    // without this, the entropy bonus's gradient (which prefers uniform)
    // flows back through the encoder, pushing it toward outputting
    // *constant* z (the degenerate maximum-entropy fixed point), which
    // collapses V→0 and π→uniform within a few hundred steps.
    //
    // For options graphs we re-run the option-conditional forward on
    // z_det. This shares the same parameter weights, so meganeura's
    // autodiff sees both forwards reusing the same params; the
    // entropy gradient hits the policy-side params (intentional —
    // pushes policy head toward uniform) but not the encoder
    // (intentional — stop_gradient).
    let total_loss = if entropy_beta == 0.0 {
        base_loss
    } else {
        let z_det = g.stop_gradient(z);
        let logits_for_ent = if num_options > 1 && per_option_heads {
            // Reuse the same fc1 + per_option_fc2 structure on z_det.
            // Per-option fc2 weights are addressed by name inside
            // `per_option_fc2`, so calling it again with the same args
            // creates duplicate ops on the same params.
            let option_onehot = option_onehot.expect("set above");
            let fc1 = nn::Linear::new(&mut g, "policy.fc1", latent_dim, hidden_dim);
            let h = fc1.forward(&mut g, z_det);
            let h = g.relu(h);
            per_option_fc2(
                &mut g,
                h,
                option_onehot,
                num_options,
                hidden_dim,
                action_dim,
            )
        } else if num_options > 1 {
            let option_onehot = option_onehot.expect("set above");
            let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
            let trunk_logits = policy.forward(&mut g, z_det);
            let option_bias =
                nn::Linear::no_bias(&mut g, "policy.option_bias", num_options, action_dim);
            let bias_out = option_bias.forward(&mut g, option_onehot);
            g.add(trunk_logits, bias_out)
        } else {
            let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
            policy.forward(&mut g, z_det)
        };
        let sm = g.softmax(logits_for_ent);
        let lsm = g.log_softmax(logits_for_ent);
        let p_log_p = g.mul(sm, lsm);
        let mean_ent = g.mean_all(p_log_p);
        let beta_input = g.input("entropy_beta", &[1]);
        let ent_penalty = g.mul(mean_ent, beta_input);
        g.add(base_loss, ent_penalty)
    };

    g.set_outputs(vec![total_loss, logits, value]);
    g
}

/// KL-penalty PPO graph with end-to-end encoder.
///
/// Replaces the clipped-surrogate of `build_ppo_policy_graph_e2e` (removed
/// in `docs/failed_experiments.md` — never converged) with a KL-divergence
/// trust-region penalty: standard plain-PG cross-entropy loss for the
/// policy gradient, plus β·KL(π_new ‖ π_old) to keep updates bounded.
///
/// Why KL instead of clip:
/// - The clipped surrogate has DEAD GRADIENT regions (when ratio is outside
///   [1-ε, 1+ε], the `greater` op's zero backward zeros the policy gradient
///   for that sample). Once a sample's ratio leaves the clip range, no
///   recovery gradient — and on kindle's small per-step batches with
///   normalized advantages, ratios drift quickly.
/// - The KL penalty has well-defined gradient EVERYWHERE; the further
///   π_new drifts from π_old, the larger the corrective force back. No
///   dead zones.
/// - Plain-PG CE loss provides the strong, well-conditioned policy
///   gradient that the clipped surrogate's `mean(min(ratio·A, clip·A))`
///   loses when normalized advantages have mean ≈ 0.
///
/// The KL is computed exactly using stored old_logits (`[batch, action_dim]`
/// input) — full distribution, not the single-sample approximation.
/// Detaches z from the value head (same fix as the failed PPO+e2e
/// debug round) to prevent value-loss-dominated encoder saturation.
///
/// Inputs:
/// - `"obs"`, `"task"`, `"action"` (advantage·one_hot): same as plain e2e.
/// - `"old_logits"`: `[batch_size, action_dim]` — π_old's pre-softmax
///   logits at action-time. Stored per-lane in the agent's transition
///   buffer alongside `prob_taken`.
/// - `"value_target"`: same as plain e2e.
///
/// Outputs: `[loss, logits, value]`.
#[allow(clippy::too_many_arguments)]
pub fn build_kl_policy_graph_e2e(
    obs_dim: usize,
    task_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    latent_dim: usize,
    batch_size: usize,
    kl_beta: f32,
    value_loss_coef: f32,
    value_clip_scale: f32,
) -> Graph {
    let mut g = Graph::new();
    let obs = g.input("obs", &[batch_size, obs_dim]);
    let task = g.input("task", &[batch_size, task_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    // old_logits input is only declared when kl_beta > 0 — meganeura
    // optimizer would prune unused inputs and break set_input calls.
    let old_logits_opt = if kl_beta > 0.0 {
        Some(g.input("old_logits", &[batch_size, action_dim]))
    } else {
        None
    };
    let value_target = g.input("value_target", &[batch_size, 1]);

    let encoder = build_named_encoder(&mut g, obs_dim, task_dim, latent_dim, hidden_dim);
    let z = encoder_forward(&mut g, &encoder, obs, task);

    let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
    let logits = policy.forward(&mut g, z);

    // Plain PG cross-entropy loss — the proven-working policy gradient
    // signal. Action input is `advantage · one_hot(taken)`, same convention
    // as build_policy_graph_e2e.
    let policy_loss = g.cross_entropy_loss(logits, action);

    // Value head — let the value gradient flow into encoder, matching
    // what the working `build_policy_graph_e2e` does.
    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);
    let value_loss_raw = g.mse_loss(value, value_target);
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let pv = g.add(policy_loss, value_loss);

    // KL(π_new ‖ π_old) = Σ_a π_new(a) · (log π_new(a) − log π_old(a)).
    // When kl_beta == 0 at construction, fully elide the KL branch
    // including the old_logits input — preserves byte-identical behavior
    // with build_policy_graph_e2e in that case (kl_beta=0 should be
    // equivalent to plain e2e).
    let (total_loss, kl_output) = if let Some(old_logits) = old_logits_opt {
        // Detach z before re-running the policy head for the KL term
        // (same fix as the entropy branch in build_policy_graph_e2e).
        // Without this, the KL gradient flows back through the encoder.
        // For near-deterministic π_old (peaked snapshot), log_softmax
        // can have very negative values for rare classes; the KL
        // gradient through these is amplified through the encoder's
        // small weights → NaN cascade in 30-50k env-steps.
        // With stop_gradient(z), the KL force only updates the policy
        // head's weights, leaving the encoder shaped purely by CE +
        // value loss. This is the same trick that fixes the entropy-
        // collapses-encoder bug on the plain e2e graph.
        let z_for_kl = g.stop_gradient(z);
        let logits_for_kl = policy.forward(&mut g, z_for_kl);
        let sm_new = g.softmax(logits_for_kl);
        let lsm_new = g.log_softmax(logits_for_kl);
        let lsm_old = g.log_softmax(old_logits);
        // log_diff = lsm_new − lsm_old via add(neg(...)) (no sub op).
        let neg_lsm_old = g.neg(lsm_old);
        let log_diff = g.add(lsm_new, neg_lsm_old);
        let kl_per_action = g.mul(sm_new, log_diff);
        let kl_mean = g.mean_all(kl_per_action);
        // Runtime-mutable beta input (shape [1]) so the harness can
        // adaptively schedule KL strength per Schulman 2017's rule:
        // observe KL, double β if KL > target·1.5, halve β if
        // KL < target/1.5. Avoids the problem of finding the right
        // fixed β at compile time.
        let kl_beta_input = g.input("kl_beta", &[1]);
        let kl_term = g.mul(kl_mean, kl_beta_input);
        (g.add(pv, kl_term), Some(kl_mean))
    } else {
        (pv, None)
    };

    // Outputs: [loss, logits, value, kl_mean] — kl_mean output
    // exposed when KL branch is on so the harness can read the
    // actual observed KL for adaptive β scheduling. When KL branch is
    // elided, only [loss, logits, value].
    if let Some(kl) = kl_output {
        g.set_outputs(vec![total_loss, logits, value, kl]);
    } else {
        g.set_outputs(vec![total_loss, logits, value]);
    }
    g
}

/// Helper: build a named encoder so the policy-side copy doesn't
/// collide parameter-names with the wm_session encoder. Uses
/// `policy_encoder.*` prefix.
fn build_named_encoder(
    g: &mut Graph,
    obs_dim: usize,
    task_dim: usize,
    latent_dim: usize,
    hidden_dim: usize,
) -> EncoderE2E {
    EncoderE2E {
        obs_proj: nn::Linear::new(g, "policy_encoder.obs_proj", obs_dim, hidden_dim),
        task_proj: nn::Linear::no_bias(g, "policy_encoder.task_proj", task_dim, hidden_dim),
        norm: nn::RmsNorm::new(g, "policy_encoder.norm.weight", hidden_dim, 1e-5),
        fc2: nn::Linear::no_bias(g, "policy_encoder.fc2", hidden_dim, latent_dim),
    }
}

struct EncoderE2E {
    obs_proj: nn::Linear,
    task_proj: nn::Linear,
    norm: nn::RmsNorm,
    fc2: nn::Linear,
}

fn encoder_forward(g: &mut Graph, e: &EncoderE2E, obs: NodeId, task: NodeId) -> NodeId {
    let h_obs = e.obs_proj.forward(g, obs);
    let h_task = e.task_proj.forward(g, task);
    let h = g.add(h_obs, h_task);
    let h = g.relu(h);
    let h = e.norm.forward(g, h);
    e.fc2.forward(g, h)
}

/// PPO clipped-surrogate policy graph with end-to-end encoder.
///
/// Restored 2026-05-01 after the autodiff bug fix — the previous
/// failure ("ratio stays near 1, clip never engages, gradient SNR too
/// low") was diagnosed under buggy autodiff (SumAll/MeanAll dropped
/// grad_output). The bug fix changes per-element gradient magnitudes,
/// so this graph is worth re-validating. Failure mode and history
/// in `docs/failed_experiments.md`.
///
/// Loss: `-mean(min(r_t·Â_t, clip(r_t, 1±ε)·Â_t)) + vf_coef·MSE(V, target) - β·H(π)`.
/// Inputs: obs, task, action (plain one-hot of taken action), advantage,
/// old_prob_taken, value_target. Optional: entropy_beta input when
/// β > 0 at construction.
#[allow(clippy::too_many_arguments)]
pub fn build_ppo_policy_graph_e2e(
    obs_dim: usize,
    task_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    latent_dim: usize,
    batch_size: usize,
    clip_eps: f32,
    value_loss_coef: f32,
    entropy_beta: f32,
    value_clip_scale: f32,
) -> Graph {
    let mut g = Graph::new();
    let obs = g.input("obs", &[batch_size, obs_dim]);
    let task = g.input("task", &[batch_size, task_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    let advantage = g.input("advantage", &[batch_size, 1]);
    let old_prob_taken = g.input("old_prob_taken", &[batch_size, 1]);
    let value_target = g.input("value_target", &[batch_size, 1]);

    let encoder = build_named_encoder(&mut g, obs_dim, task_dim, latent_dim, hidden_dim);
    let z = encoder_forward(&mut g, &encoder, obs, task);

    let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
    let logits = policy.forward(&mut g, z);

    let sm_new = g.softmax(logits);
    let p_per_class = g.mul(sm_new, action);
    let ones_k1 = g.constant(vec![1.0; action_dim], &[action_dim, 1]);
    let new_prob_taken = g.matmul(p_per_class, ones_k1);
    let ratio = g.div(new_prob_taken, old_prob_taken);

    let one_plus_eps = g.constant(vec![1.0 + clip_eps; batch_size], &[batch_size, 1]);
    let one_minus_eps = g.constant(vec![1.0 - clip_eps; batch_size], &[batch_size, 1]);
    let ones_bx1 = g.constant(vec![1.0; batch_size], &[batch_size, 1]);

    let gate_over = g.greater(ratio, one_plus_eps);
    let neg_gate_over = g.neg(gate_over);
    let inv_gate_over = g.add(ones_bx1, neg_gate_over);
    let term1 = g.mul(ratio, inv_gate_over);
    let term2 = g.mul(one_plus_eps, gate_over);
    let ratio_hi = g.add(term1, term2);

    let gate_under = g.greater(one_minus_eps, ratio_hi);
    let neg_gate_under = g.neg(gate_under);
    let inv_gate_under = g.add(ones_bx1, neg_gate_under);
    let cterm1 = g.mul(ratio_hi, inv_gate_under);
    let cterm2 = g.mul(one_minus_eps, gate_under);
    let ratio_clip = g.add(cterm1, cterm2);

    let surr1 = g.mul(ratio, advantage);
    let surr2 = g.mul(ratio_clip, advantage);
    let gate_min = g.greater(surr1, surr2);
    let neg_gate_min = g.neg(gate_min);
    let inv_gate_min = g.add(ones_bx1, neg_gate_min);
    let smin1 = g.mul(surr1, inv_gate_min);
    let smin2 = g.mul(surr2, gate_min);
    let surr_min = g.add(smin1, smin2);
    let neg_surr_min = g.neg(surr_min);
    let policy_loss = g.mean_all(neg_surr_min);

    // Detach z from value head — V MSE doesn't backprop into encoder.
    let z_for_value = g.stop_gradient(z);
    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z_for_value);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);
    let value_loss_raw = g.mse_loss(value, value_target);
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let base_loss = g.add(policy_loss, value_loss);

    let total_loss = if entropy_beta == 0.0 {
        base_loss
    } else {
        let z_det = g.stop_gradient(z);
        let logits_for_ent = policy.forward(&mut g, z_det);
        let sm = g.softmax(logits_for_ent);
        let lsm = g.log_softmax(logits_for_ent);
        let p_log_p = g.mul(sm, lsm);
        let mean_ent = g.mean_all(p_log_p);
        let beta_input = g.input("entropy_beta", &[1]);
        let ent_penalty = g.mul(mean_ent, beta_input);
        g.add(base_loss, ent_penalty)
    };

    g.set_outputs(vec![total_loss, logits, value]);
    g
}

pub fn build_continuous_policy_graph(
    latent_dim: usize,
    action_dim: usize,
    hidden_dim: usize,
    batch_size: usize,
    num_options: usize,
    per_option_heads: bool,
    value_loss_coef: f32,
    value_clip_scale: f32,
) -> Graph {
    let mut g = Graph::new();
    let z = g.input("z", &[batch_size, latent_dim]);
    let action = g.input("action", &[batch_size, action_dim]);
    let value_target = g.input("value_target", &[batch_size, 1]);

    // Phase G v2: per-option direct-to-mean bias head. See discrete
    // variant for the rationale; here the bias acts on the Gaussian
    // mean, so each option chooses a different centroid for the action
    // distribution while sharing the trunk's state-conditioned part.
    //
    // Phase G Tier-3: with `per_option_heads`, the shared fc2 is
    // replaced by N per-option heads outputting the Gaussian mean
    // directly — same gating mechanism as the discrete variant.
    let raw_mean = if num_options > 1 && per_option_heads {
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let fc1 = nn::Linear::new(&mut g, "policy.fc1", latent_dim, hidden_dim);
        let h = fc1.forward(&mut g, z);
        let h = g.relu(h);
        per_option_fc2(
            &mut g,
            h,
            option_onehot,
            num_options,
            hidden_dim,
            action_dim,
        )
    } else if num_options > 1 {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        let trunk_mean = policy.forward(&mut g, z);
        let option_onehot = g.input("option_onehot", &[batch_size, num_options]);
        let option_bias =
            nn::Linear::no_bias(&mut g, "policy.option_bias", num_options, action_dim);
        let bias_out = option_bias.forward(&mut g, option_onehot);
        g.add(trunk_mean, bias_out)
    } else {
        let policy = Policy::new(&mut g, latent_dim, action_dim, hidden_dim);
        policy.forward(&mut g, z)
    };
    // No soft-clamp on the Gaussian mean either — see the discrete
    // build_policy_graph for rationale.
    let mean = raw_mean;

    let value_head = ValueHead::new(&mut g, latent_dim, hidden_dim);
    let raw_value = value_head.forward(&mut g, z);
    let value = scaled_tanh(&mut g, raw_value, value_clip_scale, batch_size, 1);

    // Policy loss: MSE(μ, taken_action) ≡ Gaussian NLL with σ² = 1
    let policy_loss = g.mse_loss(mean, action);
    let value_loss_raw = g.mse_loss(value, value_target);
    let value_loss = if (value_loss_coef - 1.0).abs() < 1e-6 {
        value_loss_raw
    } else {
        let coef = g.scalar(value_loss_coef);
        g.mul(value_loss_raw, coef)
    };
    let total_loss = g.add(policy_loss, value_loss);

    g.set_outputs(vec![total_loss, mean, value]);
    g
}

/// Compute softmax probabilities from logits.
pub fn softmax_probs(logits: &[f32]) -> Vec<f32> {
    let max = logits.iter().cloned().fold(f32::NEG_INFINITY, f32::max);
    let exp: Vec<f32> = logits.iter().map(|&x| (x - max).exp()).collect();
    let sum: f32 = exp.iter().sum();
    exp.iter().map(|&e| e / sum).collect()
}

/// Sample an action from logits using the Gumbel-max trick.
pub fn sample_action<R: rand::Rng>(logits: &[f32], rng: &mut R) -> usize {
    let probs = softmax_probs(logits);
    let u: f32 = rng.random_range(0.0..1.0);
    let mut cumulative = 0.0;
    for (i, &p) in probs.iter().enumerate() {
        cumulative += p;
        if u < cumulative {
            return i;
        }
    }
    probs.len() - 1
}

/// Compute policy entropy: `H[π] = -Σ π_i · log π_i`.
pub fn entropy(logits: &[f32]) -> f32 {
    let probs = softmax_probs(logits);
    -probs
        .iter()
        .filter(|&&p| p > 1e-10)
        .map(|&p| p * p.ln())
        .sum::<f32>()
}

/// Sample from a diagonal Gaussian with mean `mu` and fixed std `scale`.
/// Uses the Box–Muller transform.
pub fn sample_gaussian_action<R: rand::Rng>(mu: &[f32], scale: f32, rng: &mut R) -> Vec<f32> {
    use std::f32::consts::TAU;
    mu.iter()
        .map(|&m| {
            let u1: f32 = rng.random_range(1e-7..1.0);
            let u2: f32 = rng.random_range(0.0..1.0);
            let noise = (-2.0 * u1.ln()).sqrt() * (TAU * u2).cos();
            m + scale * noise
        })
        .collect()
}
