import numpy as np

import train


def test_make_puffer_env_reset_returns_expected_batch():
    env = train.make_puffer_env(seed=123)
    try:
        obs, info = env.reset(seed=123)
        assert obs.shape == (10, train.OBS_DIM)
        assert env.single_observation_space.shape == (train.OBS_DIM,)
        assert np.isfinite(obs).all(), "reset returned NaN/Inf obs"
    finally:
        env.close()


def test_make_env_alias_steps_without_nan():
    env = train.make_env()
    try:
        obs, _ = env.reset(seed=7)
        actions = np.zeros((10, 4), dtype=np.int32)
        next_obs, rewards, terms, truncs, info = env.step(actions)

        assert obs.shape == (10, train.OBS_DIM)
        assert next_obs.shape == (10, train.OBS_DIM)
        assert rewards.shape == (10,)
        assert terms.shape == (10,)
        assert truncs.shape == (10,)
        assert np.isfinite(next_obs).all(), "step returned NaN/Inf obs"
        assert np.isfinite(rewards).all(), "step returned NaN/Inf rewards"
    finally:
        env.close()
