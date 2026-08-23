"""Minimal gym harness that trains kindle using ONLY the extrinsic-reward
primitive (no homeo, no intrinsic primitives). Diagnostic: validates
that kindle's policy-gradient machinery works on a standard RL env
where we KNOW the reward signal is learnable.

If kindle learns `CartPole-v1` via `--extrinsic-alpha 1.0`, its core RL
stack is functional and the Atari plateau is a sample-efficiency /
exploration issue specific to sparse-reward imbalanced-event envs.
If CartPole also plateaus, there's a deeper structural issue to find.

Usage:
    python python/examples/gym_extrinsic.py --env CartPole-v1 --steps 30000
    python python/examples/gym_extrinsic.py --env Pendulum-v1 --steps 30000
"""

from __future__ import annotations

import argparse
import sys
import time

import numpy as np


def _transition_observations(
    reset_obs: np.ndarray, dones: np.ndarray, infos: dict
) -> np.ndarray:
    """Replace SAME_STEP reset observations with true terminal observations."""
    if not np.any(dones):
        return reset_obs
    if "final_obs" not in infos:
        raise RuntimeError(
            "vector env omitted final_obs for a completed SAME_STEP transition"
        )
    transition_obs = reset_obs.copy()
    for lane in np.flatnonzero(dones):
        final_obs = infos["final_obs"][lane]
        if final_obs is None:
            raise RuntimeError(f"vector env omitted final_obs for lane {lane}")
        transition_obs[lane] = final_obs
    return transition_obs


def main() -> int:
    try:
        import gymnasium as gym
    except ImportError:
        print("gymnasium isn't installed.", file=sys.stderr)
        return 1
    import kindle

    parser = argparse.ArgumentParser(description=__doc__.splitlines()[0])
    parser.add_argument("--env", default="CartPole-v1")
    parser.add_argument("--lanes", type=int, default=8)
    parser.add_argument("--steps", type=int, default=30000)
    parser.add_argument("--seed", type=int, default=42)
    parser.add_argument("--log-every", type=int, default=2000)
    parser.add_argument("--lr", type=float, default=3e-4,
                        help="Base learning rate. Drives WM/encoder; the "
                        "Python binding also auto-derives lr_policy = lr/2 "
                        "unless overridden.")
    parser.add_argument("--lr-policy", type=float, default=0.0,
                        help="Override the auto-derived policy LR. 0 = use "
                        "the auto-derived value (lr/2). Useful for freezing "
                        "the encoder (set --lr 0) while training the policy.")
    parser.add_argument("--latent-dim", type=int, default=16)
    parser.add_argument("--hidden-dim", type=int, default=32)
    parser.add_argument("--action-repeat", type=int, default=1,
                        help="Repeat each chosen action for N env-steps. "
                        "Effective macro-action exploration: at N=5 random "
                        "policy produces (a,a,a,a,a)(b,b,b,b,b)... patterns "
                        "that build momentum, vs N=1 which mostly cancels "
                        "out. Try on action-sequence-bound envs "
                        "(MountainCar, Pendulum) where random per-step "
                        "actions never produce the motor sequence the env "
                        "requires.")
    parser.add_argument("--num-options", type=int, default=1,
                        help="L1 option count. >1 enables hierarchical "
                        "policy where each option is conditioned on a "
                        "different bias. Now compatible with "
                        "--end-to-end-encoder.")
    parser.add_argument("--option-horizon", type=int, default=10,
                        help="Steps an option runs before potential "
                        "termination (the L1 option_session selects a "
                        "new option every horizon steps).")
    parser.add_argument("--per-option-heads", action="store_true",
                        help="Use per-option fc2 layer instead of "
                        "shared trunk + per-option bias. Heavier but "
                        "fully decoupled per-option policies.")
    parser.add_argument("--option-entropy-beta", type=float, default=0.0,
                        help="Entropy bonus on the option_session's "
                        "option-choice distribution. > 0 prevents L1 "
                        "collapse to one option, keeps each option "
                        "exercised. Try 0.05-0.2 with --num-options >= 2.")
    parser.add_argument("--policy-head-lr-mul", type=float, default=1.0,
                        help="Multiplier on the policy.* parameter LRs "
                        "in the policy session (per-parameter LR via "
                        "meganeura's set_lr_multiplier). > 1 boosts the "
                        "actual policy head (z→logits MLP) relative to "
                        "the policy_encoder.*. Use when grad inspection "
                        "shows the encoder absorbing most gradient "
                        "while the policy head barely moves. Try 5.0-20.0.")
    parser.add_argument("--grad-debug-every", type=int, default=0,
                        help="If > 0, dump the top-5 policy-session "
                        "gradient norms (with grad/weight ratios) every "
                        "N agent-steps. Diagnostic for which parameter "
                        "is driving training instability — uses meganeura's "
                        "Session::dump_grad_summary which became available "
                        "with the grad-inspection branch.")
    parser.add_argument("--diayn-reward-alpha", type=float, default=0.0,
                        help="DIAYN intrinsic reward weight (Eysenbach "
                        "2018). Trains a discriminator q(option|z) and "
                        "adds α·(log q(option|z) − log(1/K)) to the "
                        "reward stream. Pushes options to produce "
                        "mutually-distinguishable z trajectories. "
                        "Requires --num-options >= 2. Try 0.1-1.0.")
    parser.add_argument("--n-step", type=int, default=8)
    parser.add_argument("--gamma", type=float, default=0.99)
    parser.add_argument("--advantage-clamp", type=float, default=2.0)
    parser.add_argument("--extrinsic-alpha", type=float, default=1.0)
    parser.add_argument("--reward-homeostatic", type=float, default=0.0)
    parser.add_argument("--reward-surprise", type=float, default=0.0)
    parser.add_argument("--reward-novelty", type=float, default=0.0)
    parser.add_argument("--reward-order", type=float, default=0.0)
    parser.add_argument("--rnd-reward-alpha", type=float, default=0.0,
                        help="Random Network Distillation curiosity bonus "
                        "weight. Frozen target network + trained predictor; "
                        "intrinsic reward = ||f_T(z) − f_P(z)||² / k. "
                        "Independent of WM convergence. Use for "
                        "exploration-bound envs (MountainCar, Pendulum) "
                        "where the agent never reaches the goal under random "
                        "actions. Try 0.1–1.0.")
    parser.add_argument("--entropy-beta", type=float, default=0.01)
    parser.add_argument("--replay-ratio", type=float, default=0.2,
                        help="Probability per env-step that a replay WM "
                        "step fires (samples a random transition from buffer "
                        "and runs WM forward+backward at half LR). Default "
                        "0.2 in core. Set to 0 to disable replay and check "
                        "whether it's destabilizing the encoder.")
    parser.add_argument("--watchdog", type=float, default=1000.0,
                        help="policy_loss_watchdog_threshold. When the "
                        "combined policy+value loss magnitude exceeds this, "
                        "kindle silently re-inits all policy params. Default "
                        "1000 in core, but value-MSE on dense-reward envs can "
                        "approach this — set to 1e9 to disable and check "
                        "whether the watchdog is masking an actual signal.")
    parser.add_argument("--entropy-floor", type=float, default=0.1,
                        help="Below this entropy, kindle injects a "
                        "synthetic positive advantage with uniform-smoothed "
                        "labels — forces an uncommit. Set to 0 to disable "
                        "(lets a confidently-correct policy stay committed).")
    parser.add_argument("--policy-adv-global-clip", type=float, default=0.0,
                        help="L2 norm clip on the batch-wide advantage vector "
                        "before the policy update — the policy-gradient analog "
                        "of global-grad-norm clipping. Try 1.0-5.0. 0 disables.")
    parser.add_argument("--policy-lr-adaptive-target", type=float, default=0.0,
                        help="Target |pi_loss| magnitude. When EMA(|pi_loss|) "
                        "exceeds it, per-step LR scales by target/EMA. Simple "
                        "TRPO-style damping. Try 0.5-2.0. 0 disables.")
    parser.add_argument("--policy-lr-adaptive-ema", type=float, default=0.05)
    parser.add_argument("--value-bootstrap", action="store_true",
                        help="Enable TD-bootstrap on the value-head target in "
                        "the n-step path: V_target = Σ γ^k r_{t+k} + γ^n·V(s_{t+n}). "
                        "Turns sparse external rewards into dense TD gradients "
                        "via the Bellman equation. Requires n_step ≥ 2.")
    parser.add_argument("--gae-lambda", type=float, default=0.0,
                        help="GAE λ for advantage estimation. 0 = disabled "
                        "(plain n-step advantage). 0.95 is the PPO default. "
                        "Decouples value target from advantage — prevents "
                        "value-kills-advantage collapse on dense-reward envs. "
                        "Implies value_bootstrap slot.")
    parser.add_argument("--value-loss-coef", type=float, default=1.0,
                        help="Value-head loss coefficient (PPO vf_coef). "
                        "1.0 = current behavior (value gradient dominates "
                        "on dense-reward envs). 0.5 is standard PPO. Try "
                        "0.1-0.5 to let policy gradient actually steer the "
                        "shared optimizer.")
    parser.add_argument("--value-clip-scale", type=float, default=200.0,
                        help="Soft-clamp range for V-head output (V ∈ "
                        "[-scale, +scale] via scaled_tanh). Default 200 "
                        "fits CartPole/Acrobot returns. For Pendulum "
                        "(returns -1500..0) bump to 2000.")
    parser.add_argument("--bootstrap-value-clamp", type=float, default=100.0,
                        help="Symmetric clamp on V(s_{t+n}) inside n-step "
                        "bootstrap and on V used as GAE baseline. Default "
                        "100 — kindle's pre-config value. Lower than "
                        "--value-clip-scale because stale stored V values "
                        "lag the current head. Bump for envs whose returns "
                        "exceed ±100, but expect more violent post-solve "
                        "crashes (CartPole regresses peak +329 → +64 if "
                        "raised to 200 unilaterally).")
    parser.add_argument("--recon-loss-coef", type=float, default=1.0,
                        help="Reconstruction decoder anti-collapse loss "
                        "coefficient. >0 adds a WM decoder z→obs' "
                        "+ MSE loss vs. stop_gradient(obs). Empirically "
                        "binary: any nonzero value engages the encoder "
                        "anti-collapse signal; magnitude in [0.1, 2.0] "
                        "doesn't differentiate. Validated on LunarLander "
                        "(sustained mean -291→-115 across 3 seeds at "
                        "200k×8). Default 1.0.")
    parser.add_argument("--reward-pred-loss-coef", type=float, default=0.0,
                        help="Reward-from-z auxiliary loss coefficient. "
                        ">0 adds head z→r̂ + MSE vs. per-row reward. Kills "
                        "V↔R correlation (+0.36 → +0.09); kept for the "
                        "experimental record. Default 0.0 (off).")
    parser.add_argument("--lr-drop-on-solve", type=float, default=0.0,
                        help="If > 0, drop learning_rate AND lr_policy by "
                        "this factor (e.g. 10.0 for 10× drop) once "
                        "avg_ret over the recent window exceeds "
                        "--solve-threshold for --solve-windows consecutive "
                        "log windows. One-shot per run. Targets the "
                        "post-solve crash by lowering update magnitude "
                        "after solve detected.")
    parser.add_argument("--solve-threshold", type=float, default=200.0,
                        help="avg_ret value triggering --lr-drop-on-solve.")
    parser.add_argument("--solve-windows", type=int, default=1,
                        help="Number of CONSECUTIVE log windows where "
                        "avg_ret >= --solve-threshold required before "
                        "firing the LR drop. Default 1 (immediate). Set "
                        "2-3 to wait for sustained solve and avoid firing "
                        "on a noisy first-time peak.")
    parser.add_argument("--require-recent-return", type=float, default=None,
                        help="Exit non-zero unless the final recent-episode "
                        "mean reaches this value. Turns the harness into a "
                        "reproducible learning gate (195 for CartPole-v1).")
    parser.add_argument("--recent-episodes-per-lane", type=int, default=5,
                        help="Completed episodes retained per lane for the "
                        "final --require-recent-return gate.")
    parser.add_argument("--solve-auto-multiple", type=float, default=0.0,
                        help="Auto-threshold: when > 0, ignore "
                        "--solve-threshold and instead trigger LR-drop "
                        "when avg_ret >= multiple × early-baseline (mean "
                        "of first 3 log windows after warmup). Robust "
                        "across envs since it's relative to the env's own "
                        "random-policy floor. Try 5.0 — fires when agent "
                        "is doing 5× better than random.")
    parser.add_argument("--solve-auto-warmup-windows", type=int, default=2,
                        help="Number of initial log windows to skip when "
                        "computing the auto-threshold baseline (lets the "
                        "agent settle past the noisy first-tick state).")
    parser.add_argument("--entropy-beta-final", type=float, default=None,
                        help="If set, linearly anneal --entropy-beta from "
                        "its initial value to this final value over "
                        "--entropy-decay-steps env-steps. Targets local-"
                        "optimum policy plateaus (LunarLander) — high "
                        "early entropy keeps exploration alive past the "
                        "plateau, decay to 0 lets the policy commit late. "
                        "Only effective with --end-to-end-encoder (where "
                        "entropy_beta is a graph input).")
    parser.add_argument("--entropy-decay-steps", type=int, default=0,
                        help="Number of agent-steps over which to linearly "
                        "decay entropy_beta to --entropy-beta-final. Set "
                        "to ~half of --steps for a typical schedule.")
    parser.add_argument("--policy-update-interval", type=int, default=1,
                        help="Update policy only every N env-steps, then do "
                        "N gradient steps on the accumulated rollout "
                        "(A2C/PPO-style). 1 = per-env-step (default). "
                        "Try n_step+1 (e.g. 9) to keep the rollout fully "
                        "on-policy with respect to the collector.")
    parser.add_argument("--advantage-normalize", action="store_true",
                        help="Zero-mean / unit-std the advantages per batch "
                        "before the policy update (standard PPO/A2C trick). "
                        "Strips the \"V lags reward\" bias — critical early "
                        "in training when V hasn't caught up and every "
                        "advantage is same-sign.")
    parser.add_argument("--use-grpo", action="store_true",
                        help="Normalize policy advantages among parallel "
                        "forks of this task instead of using the value "
                        "baseline. Requires --advantage-normalize.")
    parser.add_argument("--use-grpo-episode", action="store_true",
                        help="With --use-grpo, rank completed whole-episode "
                        "returns across lanes. Useful when per-step rewards "
                        "are uninformative but episode length/outcome is not.")
    parser.add_argument("--use-sil", action="store_true",
                        help="Replay actions from completed episodes whose "
                        "return beats the moving baseline (self-imitation).")
    parser.add_argument("--sil-loss-coef", type=float, default=1.0,
                        help="Weight of the self-imitation update when "
                        "--use-sil is enabled.")
    parser.add_argument("--use-ppo", action="store_true",
                        help="Use the PPO clipped-surrogate policy loss. "
                        "Requires policy_update_interval > 1 to exercise the "
                        "ratio. Incompatible with L1 options for now.")
    parser.add_argument("--ppo-clip-eps", type=float, default=0.2,
                        help="PPO clip radius ε; ratio is clamped to "
                        "[1-ε, 1+ε]. Standard 0.2.")
    parser.add_argument("--use-kl-ppo", action="store_true",
                        help="Use the KL-penalty PPO graph (e2e only). "
                        "Plain-PG cross-entropy + β·KL(π_new ‖ π_old). "
                        "Replaces the failed clipped-surrogate PPO+e2e "
                        "(see docs/failed_experiments.md). KL has well-"
                        "defined gradient everywhere — no dead clip zones. "
                        "Requires --end-to-end-encoder; mutually exclusive "
                        "with --use-ppo and L1 options.")
    parser.add_argument("--kl-beta", type=float, default=0.05,
                        help="KL penalty weight for --use-kl-ppo. Larger "
                        "= tighter trust region. Try 0.01-0.5.")
    parser.add_argument("--kl-target", type=float, default=0.0,
                        help="If > 0, enable Schulman 2017's adaptive β: "
                        "after each training step read observed KL, "
                        "double β if KL > target·1.5, halve if "
                        "KL < target/1.5. Bounds β to [1e-4, 10]. "
                        "Standard target value 0.01-0.05.")
    parser.add_argument("--kl-use-snapshot", action="store_true",
                        help="With --use-kl-ppo, freeze π_old at start of "
                        "each K-epoch cycle (forward pass on the rollout "
                        "with current weights, captured logits used for "
                        "all K training epochs). Standard PPO behavior. "
                        "Without this flag, kindle uses per-transition "
                        "logits_at_action which keeps π_old very close to "
                        "π_new (KL near zero, trust region inactive).")
    parser.add_argument("--ppo-n-epochs", type=int, default=1,
                        help="Number of epochs to replay each rollout "
                        "through the PPO update. Only matters with "
                        "--use-ppo. Standard 3-10. On epoch 1 ratio ≈ 1 "
                        "(no clip activity); epochs 2+ exercise the clip.")
    parser.add_argument("--rollout-length", type=int, default=1,
                        help="A2C-style rollout buffer length. Policy "
                        "graph batch_size becomes lanes×rollout_length; "
                        "one policy session.step() per update covers the "
                        "whole rollout at once. Supersedes "
                        "--policy-update-interval when > 1. Try 8-32.")
    parser.add_argument("--end-to-end-encoder", action="store_true",
                        help="Use end-to-end encoder + policy + value graph "
                        "(policy_encoder.* params, separate from wm_session). "
                        "Encoder receives gradient from both value MSE and "
                        "policy CE. Required to actually solve CartPole — "
                        "without this, kindle's encoder is trained only by "
                        "WM next-state-prediction loss and produces features "
                        "that aren't policy-discriminative.")
    parser.add_argument("--recompute-base-v", action="store_true",
                        help="Recompute V on ripe.latent at training time "
                        "instead of using stored ripe.value (which was "
                        "computed under a stale encoder n_step env-steps "
                        "ago). Adds one forward pass per training step.")
    parser.add_argument("--policy-warmup-steps", type=int, default=0,
                        help="Zero advantages for the first N env-steps, "
                        "so only the value head trains. Lets V catch up "
                        "to reward scale before policy starts committing. "
                        "Try 2000-10000 on dense-reward envs.")
    parser.add_argument("--async-envs", action="store_true")
    parser.add_argument("--discretize-buckets", type=int, default=5,
                        help="For continuous-action envs (Pendulum, etc.), "
                        "discretize the action space into N evenly-spaced "
                        "buckets so PyBatchAgent's discrete adapter can drive "
                        "them. Pendulum needs ≥5 to be solvable.")
    args = parser.parse_args()
    if args.use_grpo and not args.advantage_normalize:
        parser.error("--use-grpo requires --advantage-normalize")
    if args.use_grpo_episode and not args.use_grpo:
        parser.error("--use-grpo-episode requires --use-grpo")

    # PyBatchAgent forces discrete actions. For continuous envs
    # (Pendulum, etc.), wrap them with a Discretize wrapper that
    # buckets the action space into N evenly-spaced points.
    class Discretize(gym.ActionWrapper):
        def __init__(self, env, n_buckets):
            super().__init__(env)
            self.n_buckets = n_buckets
            self.action_space = gym.spaces.Discrete(n_buckets)
            low = env.action_space.low
            high = env.action_space.high
            self._lookup = np.linspace(low, high, n_buckets)

        def action(self, act):
            return self._lookup[int(act)].astype(np.float32)

    def make_env():
        e = gym.make(args.env)
        if not isinstance(e.action_space, gym.spaces.Discrete):
            e = Discretize(e, args.discretize_buckets)
        return e

    thunks = [lambda i=i: make_env() for i in range(args.lanes)]
    autoreset_mode = gym.vector.AutoresetMode.SAME_STEP
    if args.async_envs:
        envs = gym.vector.AsyncVectorEnv(
            thunks, shared_memory=True, autoreset_mode=autoreset_mode
        )
    else:
        envs = gym.vector.SyncVectorEnv(thunks, autoreset_mode=autoreset_mode)
    obs_batch, _ = envs.reset(seed=args.seed)
    obs_dim = obs_batch.shape[-1]
    act_space = envs.single_action_space
    is_discrete = isinstance(act_space, gym.spaces.Discrete)
    if not is_discrete:
        # make_env() discretizes Box action spaces; anything else
        # (MultiDiscrete, Tuple, …) has no adapter in this harness.
        raise NotImplementedError(
            f"unsupported action space {act_space!r}: this harness only "
            "drives Discrete spaces (Box spaces are auto-wrapped in "
            "Discretize by make_env)"
        )
    num_actions = int(act_space.n) if is_discrete else int(np.prod(act_space.shape))
    print(
        f"env={args.env} lanes={args.lanes} obs_dim={obs_dim} "
        f"{'discrete' if is_discrete else 'continuous'} actions={num_actions}"
    )

    agent = kindle.BatchAgent(
        obs_dim=obs_dim,
        num_actions=num_actions,
        batch_size=args.lanes,
        env_ids=[0] * args.lanes,
        seed=args.seed,
        learning_rate=args.lr,
        lr_policy=args.lr_policy if args.lr_policy > 0 else None,
        latent_dim=args.latent_dim,
        hidden_dim=args.hidden_dim,
        action_repeat=args.action_repeat,
        num_options=args.num_options,
        option_horizon=args.option_horizon,
        per_option_heads=args.per_option_heads,
        option_entropy_beta=args.option_entropy_beta,
        diayn_reward_alpha=args.diayn_reward_alpha,
        n_step=args.n_step,
        gamma=args.gamma,
        advantage_clamp=args.advantage_clamp,
        entropy_beta=args.entropy_beta,
        entropy_floor=args.entropy_floor,
        policy_loss_watchdog_threshold=args.watchdog,
        replay_ratio=args.replay_ratio,
        reward_homeostatic=args.reward_homeostatic,
        reward_surprise=args.reward_surprise,
        reward_novelty=args.reward_novelty,
        reward_order=args.reward_order,
        rnd_reward_alpha=args.rnd_reward_alpha,
        extrinsic_reward_alpha=args.extrinsic_alpha,
        policy_adv_global_clip=args.policy_adv_global_clip if args.policy_adv_global_clip > 0 else None,
        policy_lr_adaptive_target=args.policy_lr_adaptive_target if args.policy_lr_adaptive_target > 0 else None,
        policy_lr_adaptive_ema=args.policy_lr_adaptive_ema,
        value_bootstrap=args.value_bootstrap,
        gae_lambda=args.gae_lambda if args.gae_lambda > 0 else None,
        value_loss_coef=args.value_loss_coef,
        policy_update_interval=args.policy_update_interval,
        advantage_normalize=args.advantage_normalize,
        use_grpo=args.use_grpo,
        use_grpo_episode=args.use_grpo_episode,
        use_sil=args.use_sil,
        sil_loss_coef=args.sil_loss_coef,
        use_ppo=args.use_ppo,
        ppo_clip_eps=args.ppo_clip_eps,
        use_kl_ppo=args.use_kl_ppo,
        kl_beta=args.kl_beta,
        kl_use_snapshot=args.kl_use_snapshot,
        ppo_n_epochs=args.ppo_n_epochs,
        policy_warmup_steps=args.policy_warmup_steps,
        recompute_base_v=args.recompute_base_v,
        end_to_end_encoder=args.end_to_end_encoder,
        rollout_length=args.rollout_length,
        value_clip_scale=args.value_clip_scale,
        bootstrap_value_clamp=args.bootstrap_value_clamp,
        recon_loss_coef=args.recon_loss_coef,
        reward_pred_loss_coef=args.reward_pred_loss_coef,
    )
    print("agent ready (MLP encoder)")

    # Effective policy LR actually in use: the explicit --lr-policy
    # override, or the binding's auto-derived lr × 0.5 (the constructor
    # sets config.lr_policy = lr * 0.5 when lr_policy is None — see
    # python/src/lib.rs). The --lr-drop-on-solve path must divide THIS,
    # not the 0.0 sentinel default, or the drop freezes the policy.
    effective_lr_policy = args.lr_policy if args.lr_policy > 0 else args.lr * 0.5

    if args.policy_head_lr_mul != 1.0:
        agent.set_policy_lr_multiplier("policy.", args.policy_head_lr_mul)
        print(f"[policy-head LR multiplier] policy.* params × {args.policy_head_lr_mul}")

    ep_returns = [[] for _ in range(args.lanes)]
    cur_ret = np.zeros(args.lanes, dtype=np.float64)
    ep_count = 0
    t0 = time.time()

    # Track running KL beta when adaptive mode is on.
    kl_beta_state = [args.kl_beta]

    for step in range(args.steps):
        # Adaptive KL-β schedule (Schulman 2017).
        if args.kl_target > 0 and args.use_kl_ppo and step > 100:
            kl_obs = float(agent.last_kl())
            if kl_obs > args.kl_target * 1.5:
                kl_beta_state[0] = min(10.0, kl_beta_state[0] * 1.5)
                agent.set_kl_beta(kl_beta_state[0])
            elif kl_obs < args.kl_target / 1.5:
                kl_beta_state[0] = max(1e-4, kl_beta_state[0] / 1.5)
                agent.set_kl_beta(kl_beta_state[0])
        # Linear entropy_beta schedule.
        if (args.entropy_beta_final is not None
                and args.entropy_decay_steps > 0):
            t = min(1.0, step / args.entropy_decay_steps)
            beta_t = (1.0 - t) * args.entropy_beta + t * args.entropy_beta_final
            agent.set_entropy_beta(float(beta_t))
        # Normalize obs lists to list-of-lists for kindle.act()
        obs_lists = [obs_batch[i].astype(np.float32).tolist() for i in range(args.lanes)]
        actions = agent.act(obs_lists)
        # Always discrete: make_env() wraps continuous-action envs in
        # Discretize (the old `else` branch here was unreachable and
        # would have sent action INDICES as continuous action values).
        actions_np = np.array(actions, dtype=np.int64)
        next_obs, rewards, terms, truncs, infos = envs.step(actions_np)
        cur_ret += rewards
        dones = np.logical_or(terms, truncs)
        transition_obs = _transition_observations(next_obs, dones, infos)

        # Extrinsic reward — the only training signal.
        agent.set_extrinsic_reward(rewards.astype(np.float32, copy=False))
        transition_lists = [
            transition_obs[i].astype(np.float32).tolist()
            for i in range(args.lanes)
        ]
        agent.observe(
            transition_lists,
            [int(a) for a in actions],
            homeostatic=[[] for _ in range(args.lanes)],
        )

        for i, done in enumerate(dones):
            if done:
                ep_returns[i].append(float(cur_ret[i]))
                cur_ret[i] = 0.0
                ep_count += 1
                agent.mark_boundary(i)
        obs_batch = next_obs

        if (args.grad_debug_every > 0
                and step > 0
                and step % args.grad_debug_every == 0):
            print(f"[grad-debug step={step}]")
            agent.dump_policy_grad_summary(5)
        if args.log_every and step > 0 and step % args.log_every == 0:
            diags = agent.diagnostics()
            d = diags[0]
            all_recent = [
                r
                for lane_rets in ep_returns
                for r in lane_rets[-args.recent_episodes_per_lane:]
            ]
            avg_ret = sum(all_recent) / max(1, len(all_recent))
            # One-shot LR drop on sustained solve detection.
            # Requires `--solve-windows` consecutive windows above
            # threshold to avoid firing on a noisy first-time peak
            # (which can lock in a transient policy that's about to
            # uncommit on its own).
            if args.lr_drop_on_solve > 0 and not getattr(main, "_lr_dropped", False):
                # Auto-threshold: build baseline from first
                # `solve_auto_warmup_windows` post-warmup logs, then
                # trigger when avg_ret >= multiple × baseline.
                if args.solve_auto_multiple > 0:
                    main._auto_baseline_window_returns = (
                        getattr(main, "_auto_baseline_window_returns", []) + [avg_ret]
                    )
                    auto_warmup = args.solve_auto_warmup_windows
                    baseline_n = auto_warmup
                    if len(main._auto_baseline_window_returns) <= baseline_n:
                        # Still building baseline; can't fire yet.
                        threshold = float("inf")
                    else:
                        baseline = (
                            sum(main._auto_baseline_window_returns[:baseline_n])
                            / baseline_n
                        )
                        # Use abs() so negative-reward envs (Acrobot,
                        # Pendulum) work too. "Multiple × random" means
                        # the agent's avg has shrunk in absolute distance
                        # from 0 by that factor.
                        if baseline >= 0:
                            threshold = args.solve_auto_multiple * baseline
                        else:
                            threshold = baseline / args.solve_auto_multiple
                else:
                    threshold = args.solve_threshold
                if avg_ret >= threshold:
                    main._solve_streak = getattr(main, "_solve_streak", 0) + 1
                else:
                    main._solve_streak = 0
                if main._solve_streak >= args.solve_windows:
                    new_lr = args.lr / args.lr_drop_on_solve
                    # Drop from the EFFECTIVE policy LR (auto-derived
                    # lr/2 unless --lr-policy overrode it) — dividing
                    # the 0.0 sentinel set the policy LR to exactly 0
                    # and froze learning at solve time.
                    new_lr_policy = effective_lr_policy / args.lr_drop_on_solve
                    agent.set_learning_rate(new_lr)
                    agent.set_lr_policy(new_lr_policy)
                    main._lr_dropped = True
                    print(f"[lr-drop] step={step} avg_ret={avg_ret:+.1f} "
                          f"threshold={threshold:+.1f} "
                          f"streak={main._solve_streak} "
                          f"→ lr {args.lr:.1e} → {new_lr:.1e}, "
                          f"lr_policy {effective_lr_policy:.1e} → {new_lr_policy:.1e}")
            elapsed = time.time() - t0
            sps = step * args.lanes / max(1e-3, elapsed)
            # Per-lane V and entropy distribution: V std across lanes
            # tells us whether the value head is discriminating between
            # different states (high std) or predicting the mean
            # everywhere (std ≈ 0). Same for entropy.
            vs = np.array(agent.values(), dtype=np.float32)
            ents = np.array(agent.entropies(), dtype=np.float32)
            kl_str = ""
            if args.use_kl_ppo:
                kl_str = (f" | KL={float(agent.last_kl()):.4f} "
                          f"β={kl_beta_state[0]:.4f}")
            print(
                f"step={step:>6} eps={ep_count:>3} avg_ret={avg_ret:+7.1f} "
                f"| wm={float(d['loss_world_model']):.3f} "
                f"pi={float(d['loss_policy']):+6.2f} "
                f"ent={float(d['policy_entropy']):.2f} "
                f"r={float(d['reward_mean']):+5.2f} "
                f"| V[{vs.min():+5.2f}, {vs.max():+5.2f}] σV={vs.std():.2f} "
                f"σE={ents.std():.2f}"
                f"{kl_str}"
                f" | {sps:5.0f} env-steps/s"
            )

    envs.close()
    elapsed = time.time() - t0
    total_eps = sum(len(r) for r in ep_returns)
    if total_eps > 0:
        mean_ret = sum(r for lane in ep_returns for r in lane) / total_eps
    else:
        mean_ret = float("nan")
    print(f"\n--- {args.env} summary ---")
    print(f"total env-steps: {args.steps * args.lanes}")
    print(f"episodes: {total_eps}, mean return: {mean_ret:+.2f}")
    final_recent = [
        r
        for lane_rets in ep_returns
        for r in lane_rets[-args.recent_episodes_per_lane:]
    ]
    recent_mean = (
        sum(final_recent) / len(final_recent)
        if final_recent
        else float("nan")
    )
    print(
        f"recent episodes: {len(final_recent)}, "
        f"recent mean return: {recent_mean:+.2f}"
    )
    print(
        f"wall: {elapsed:.1f}s, throughput: "
        f"{args.steps * args.lanes / max(1e-3, elapsed):.0f} env-steps/s"
    )
    if args.require_recent_return is not None:
        passed = bool(final_recent) and recent_mean >= args.require_recent_return
        print(
            "learning gate: "
            f"{'PASS' if passed else 'FAIL'} "
            f"(recent {recent_mean:+.2f} vs required "
            f"{args.require_recent_return:+.2f})"
        )
        return 0 if passed else 2
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
