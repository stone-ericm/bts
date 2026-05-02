"""Tests for cross-fitted DR-OPE on the BTS MDP."""
from __future__ import annotations

import numpy as np
import pandas as pd
import pytest

from bts.validate.ope import fitted_q_evaluation


class TestFittedQEvaluation:
    def test_fqe_recovers_true_value_on_toy_mdp(self, toy_mdp_2state_2action):
        """FQE on synthetic data from the toy MDP should match analytical truth."""
        rng = np.random.default_rng(42)
        mdp = toy_mdp_2state_2action

        n_trajectories = 5000
        rows = []
        for _ in range(n_trajectories):
            s = 0
            for t in range(mdp["horizon"]):
                a = 1  # always advance
                next_states, probs = zip(*mdp["transitions"][(s, a)].items())
                sn = rng.choice(next_states, p=probs)
                r = mdp["rewards"](s, a, sn)
                rows.append({"t": t, "s": s, "a": a, "sn": sn, "r": r})
                s = sn

        df = pd.DataFrame(rows)
        target_policy = lambda s, t: 1  # always advance

        v_hat = fitted_q_evaluation(
            df, target_policy, n_states=2, n_actions=2, horizon=mdp["horizon"]
        )

        true_v = mdp["true_value"]["always_advance"]
        assert abs(v_hat - true_v) < 0.03, f"FQE recovered {v_hat:.4f} vs true {true_v:.4f}"
