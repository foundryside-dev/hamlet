"""
Integration tests for recurrent networks (LSTM) in Townlet.

Tests LSTM hidden state management, batch training, and POMDP integration.
Covers both migrated tests from test_lstm_temporal_learning.py and new critical tests.

Test Organization:
- TestLSTMHiddenStatePersistence: Hidden state lifecycle during episodes (4 tests)
- TestLSTMBatchTraining: Batch training with sequences (3 tests - 1 new + 2 migrated)
- TestLSTMForwardPass: Forward pass with POMDP (1 test)
"""

from pathlib import Path

import pytest
import torch
import torch.nn.functional as functional

from tests.test_townlet.helpers.config_builder import mutate_curriculum_yaml, mutate_stratum_yaml
from townlet.agent.networks import RecurrentSpatialQNetwork
from townlet.curriculum.static import StaticCurriculum
from townlet.exploration.epsilon_greedy import EpsilonGreedyExploration
from townlet.population.vectorized import VectorizedPopulation
from townlet.training.sequential_replay_buffer import SequentialReplayBuffer

pytestmark = pytest.mark.slow

# =============================================================================
# TEST CLASS 1: LSTM Hidden State Persistence
# =============================================================================


class TestLSTMHiddenStatePersistence:
    """Test LSTM hidden state lifecycle during episode execution."""

    def test_hidden_state_persists_across_10_steps_within_episode(
        self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config
    ):
        """
        Verify hidden state evolves during episode rollout.

        Hidden state should change across steps as the agent accumulates
        experience, demonstrating that memory is being built up.
        """

        def _modifier(cfg):
            training = cfg["training"]
            training_loop = training["training_loop"]
            training_loop["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="lstm_hidden_state_survival")

        # Switch to partial observability and shrink grid to 5x5
        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5}),
        )
        mutate_stratum_yaml(
            config_dir,
            lambda s: s["stratum"]["substrate"]["grid"].update({"width": 5, "height": 5}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=1)

        # Create recurrent population
        curriculum = StaticCurriculum()
        exploration = EpsilonGreedyExploration(
            epsilon=0.1,
            epsilon_min=0.1,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            # action_dim defaults to env.action_dim
            brain_config=recurrent_brain_config,
            vision_window_size=5,
            batch_size=8,
            train_frequency=10000,  # Disable training (test focuses on hidden state persistence)
        )

        # Reset environment and population
        population.reset()

        # Initialize all meters to 1.0 to prevent cascade-induced death during test
        env.meters.fill_(1.0)

        # Capture initial rollout memory (population-owned since WS-1(b))
        assert population.rollout_hidden is not None
        h0, c0 = population.rollout_hidden
        hidden_states = [(h0.clone(), c0.clone())]

        # Run 10 steps and verify agent survives
        for step_num in range(10):
            state = population.step_population(env)
            # Ensure agent didn't die (would reset hidden state and break test)
            assert not state.dones[0], (
                f"Agent died at step {step_num + 1}/10. "
                f"Energy: {env.meters[0, 0]:.3f}, Health: {env.meters[0, 6]:.3f}. "
                "This test requires agent to survive 10 steps to verify hidden state persistence. "
                "If this fails, energy costs may need to be reduced further."
            )
            h, c = population.rollout_hidden
            hidden_states.append((h.clone(), c.clone()))

        # Verify hidden state changed across steps
        for i in range(len(hidden_states) - 1):
            h_curr, c_curr = hidden_states[i]
            h_next, c_next = hidden_states[i + 1]

            # Hidden states should be different (memory evolving)
            assert not torch.allclose(h_curr, h_next, atol=1e-6), f"Hidden state should change between steps {i} and {i + 1}"
            assert not torch.allclose(c_curr, c_next, atol=1e-6), f"Cell state should change between steps {i} and {i + 1}"

    def test_hidden_state_resets_on_death(self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config):
        """
        Verify hidden state resets when agent dies.

        When agent dies, hidden state should be reset to zeros to prevent
        memory contamination across episodes.
        """
        # Seed RNG for deterministic behavior in full suite
        torch.manual_seed(42)

        def _modifier(cfg):
            training = cfg["training"]
            training_loop = training["training_loop"]
            training_loop["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="lstm_hidden_state_reset")

        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5}),
        )
        mutate_stratum_yaml(
            config_dir,
            lambda s: s["stratum"]["substrate"]["grid"].update({"width": 5, "height": 5}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=1)

        curriculum = StaticCurriculum()
        exploration = EpsilonGreedyExploration(
            epsilon=0.0,  # Greedy for determinism
            epsilon_min=0.0,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            # action_dim defaults to env.action_dim
            brain_config=recurrent_brain_config,
            vision_window_size=5,
            train_frequency=10000,  # Disable training (test focuses on death reset)
        )

        population.reset()

        # Run until death (energy drains to 0)
        max_steps = 200  # Safety limit
        done = False
        for step in range(max_steps):
            state = population.step_population(env)
            if state.dones[0]:
                done = True
                break

        assert done, "Agent should have died"

        # After death, rollout memory should be zeros
        assert population.rollout_hidden is not None
        h, c = population.rollout_hidden

        assert torch.allclose(h, torch.zeros_like(h)), "Hidden state should be zeros after death"
        assert torch.allclose(c, torch.zeros_like(c)), "Cell state should be zeros after death"

    def test_hidden_state_resets_after_flush_on_max_steps(self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config):
        """
        Verify hidden state resets after flush_episode() on max_steps survival.

        When agent survives max_steps, flush_episode() should reset hidden state
        to prevent memory leakage into next episode.
        """

        def _modifier(cfg):
            training_loop = cfg["training"]["training_loop"]
            training_loop["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="lstm_hidden_state_flush")

        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5}),
        )
        mutate_stratum_yaml(
            config_dir,
            lambda s: s["stratum"]["substrate"]["grid"].update({"width": 5, "height": 5}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=1)

        curriculum = StaticCurriculum()
        exploration = EpsilonGreedyExploration(
            epsilon=0.1,
            epsilon_min=0.1,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            # action_dim defaults to env.action_dim
            brain_config=recurrent_brain_config,
            vision_window_size=5,
            train_frequency=10000,  # Disable training (test focuses on flush behavior)
        )

        population.reset()

        # Initialize all meters to 1.0 to prevent cascade-induced death during test
        env.meters.fill_(1.0)

        # Run 50 steps (no death expected)
        for _ in range(50):
            population.step_population(env)

        # Flush episode (max_steps survival)
        population.flush_episode(agent_idx=0)

        # Rollout memory should be zeros after flush
        assert population.rollout_hidden is not None
        h, c = population.rollout_hidden

        assert torch.allclose(h, torch.zeros_like(h)), "Hidden state should be zeros after flush"
        assert torch.allclose(c, torch.zeros_like(c)), "Cell state should be zeros after flush"

    def test_hidden_state_shape_correct_during_episode(self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config):
        """
        Verify hidden state shape during multi-agent rollout.

        Hidden state shape should be [1, num_agents, 256] throughout episode.
        """

        # Create environment with 2 agents
        # Use VERY low energy costs to ensure agents survive 10 steps
        def _modifier(cfg):
            training_loop = cfg["training"]["training_loop"]
            training_loop["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="lstm_hidden_state_shape")

        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5}),
        )
        mutate_stratum_yaml(
            config_dir,
            lambda s: s["stratum"]["substrate"]["grid"].update({"width": 5, "height": 5}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=2)

        curriculum = StaticCurriculum()
        exploration = EpsilonGreedyExploration(
            epsilon=0.1,
            epsilon_min=0.1,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0", "agent_1"],
            device=cpu_device,
            # action_dim defaults to env.action_dim
            brain_config=recurrent_brain_config,
            vision_window_size=5,
            train_frequency=10000,  # Disable training (test focuses on shape verification)
        )

        population.reset()

        # Initialize all meters to 1.0 to prevent cascade-induced death during test
        env.meters.fill_(1.0)

        # Verify initial shape
        assert population.rollout_hidden is not None
        h, c = population.rollout_hidden
        assert h.shape == (1, 2, 256), f"Expected shape (1, 2, 256), got {h.shape}"
        assert c.shape == (1, 2, 256), f"Expected shape (1, 2, 256), got {c.shape}"

        # Run 10 steps and verify shape remains consistent
        for _ in range(10):
            population.step_population(env)
            h, c = population.rollout_hidden
            assert h.shape == (1, 2, 256), f"Hidden state shape should be (1, 2, 256), got {h.shape}"
            assert c.shape == (1, 2, 256), f"Cell state shape should be (1, 2, 256), got {c.shape}"


# =============================================================================
# TEST CLASS 2: LSTM Batch Training
# =============================================================================


class TestLSTMBatchTraining:
    """Test LSTM batch training with sequence sampling."""

    def test_hidden_state_batch_size_correct_during_training(
        self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config
    ):
        """
        Verify hidden state shape changes from num_agents to batch_size during training.

        During episode: [1, num_agents, 256]
        During training: [1, batch_size, 256]
        After training: [1, num_agents, 256]
        """

        def _modifier(cfg):
            training_loop = cfg["training"]["training_loop"]
            training_loop["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="lstm_batch_size")

        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5}),
        )
        mutate_stratum_yaml(
            config_dir,
            lambda s: s["stratum"]["substrate"]["grid"].update({"width": 5, "height": 5}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=2)

        curriculum = StaticCurriculum()
        exploration = EpsilonGreedyExploration(
            epsilon=0.1,
            epsilon_min=0.1,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0", "agent_1"],
            device=cpu_device,
            # action_dim defaults to env.action_dim
            brain_config=recurrent_brain_config,
            vision_window_size=5,
            batch_size=8,
            train_frequency=4,
        )

        population.reset()

        # Initialize all meters to 1.0 to prevent cascade-induced death during test
        env.meters.fill_(1.0)

        # Verify initial shape (episode batch size = num_agents)
        assert population.rollout_hidden is not None
        h, c = population.rollout_hidden
        assert h.shape == (1, 2, 256), f"Initial hidden state should be (1, 2, 256), got {h.shape}"

        # Run enough steps to trigger training (need 16+ episodes in buffer)
        # Each episode needs to die to be stored
        for episode in range(20):
            # Run until death
            for step in range(100):
                state = population.step_population(env)
                if state.dones.any():
                    break

        # Training must not touch the rollout memory: still num_agents-shaped
        h, c = population.rollout_hidden
        assert h.shape == (1, 2, 256), f"After training, hidden state should be (1, 2, 256), got {h.shape}"

    def test_lstm_training_with_sequences(self, cpu_device):
        """
        Test that LSTM can learn a simple temporal pattern: A → B → C.

        Migrated from test_lstm_temporal_learning.py::test_lstm_learns_temporal_sequence.

        Task: Learn that action sequences matter
        - State 0 (start) → State 1: Take action 0
        - State 1 → State 2 (goal): Take action 1
        - Reward only given at State 2

        An MLP would struggle (state 1 looks the same whether you came from 0 or elsewhere).
        An LSTM should learn the temporal dependency.
        """
        # Simple network for testing
        network = RecurrentSpatialQNetwork(
            action_dim=2,  # Actions: 0 (A→B) or 1 (B→C)
            window_size=1,  # Minimal spatial observation
            position_dim=2,
            bars_dim=2,  # Minimal state (just state_id encoded)
            num_affordance_types=1,
            enable_temporal_features=False,
            hidden_dim=32,  # Small for fast training
        ).to(cpu_device)

        optimizer = torch.optim.Adam(network.parameters(), lr=0.01)

        # Create synthetic episode: State 0 → State 1 → State 2
        # Observation encoding: [grid (1), pos (2), meters (2), affordance (2)] = 7 dims
        # State 0: meters = [1.0, 0.0]
        # State 1: meters = [0.5, 0.5]
        # State 2: meters = [0.0, 1.0]

        def make_observation(state_id):
            """Create synthetic observation for a state."""
            grid = torch.zeros(1)  # Minimal grid
            pos = torch.tensor([0.0, 0.0])  # Fixed position

            if state_id == 0:
                meters = torch.tensor([1.0, 0.0])
            elif state_id == 1:
                meters = torch.tensor([0.5, 0.5])
            else:  # state_id == 2
                meters = torch.tensor([0.0, 1.0])

            affordance = torch.zeros(2)  # No affordance

            return torch.cat([grid, pos, meters, affordance])

        # Create training episode: 0 → 1 → 2
        episode = {
            "observations": torch.stack(
                [
                    make_observation(0),
                    make_observation(1),
                    make_observation(2),
                ]
            ),
            "actions": torch.tensor([0, 1, 0]),  # A→B, B→C, done
            "rewards": torch.tensor([0.0, 0.0, 1.0]),  # Combined reward only at end
            "dones": torch.tensor([False, False, True]),
        }

        # Store episode in replay buffer
        replay_buffer = SequentialReplayBuffer(capacity=100, device=cpu_device)
        replay_buffer.store_episode(episode)

        # Store a few more episodes for sampling variety
        for _ in range(15):
            replay_buffer.store_episode(episode)

        # Create target network (for stable temporal learning)
        target_network = RecurrentSpatialQNetwork(
            action_dim=2,
            window_size=1,
            position_dim=2,
            bars_dim=2,
            num_affordance_types=1,
            enable_temporal_features=False,
            hidden_dim=32,
        ).to(cpu_device)
        target_network.load_state_dict(network.state_dict())
        target_network.eval()

        # Train for multiple iterations
        losses = []
        for iteration in range(500):  # More iterations for convergence
            # Sample sequence
            batch = replay_buffer.sample_sequences(
                batch_size=8,
                seq_len=3,
                intrinsic_weight=0.0,
            )

            gamma = 0.99

            # PASS 1: Collect Q-predictions from online network, threading hidden state
            hidden = network.initial_hidden(8, cpu_device)
            q_pred_list = []

            for t in range(3):
                q_values, hidden = network(batch["observations"][:, t, :], hidden)
                q_pred = q_values.gather(1, batch["actions"][:, t].unsqueeze(1)).squeeze()
                q_pred_list.append(q_pred)

            # PASS 2: Collect Q-targets from target network, threading hidden state
            with torch.no_grad():
                target_hidden = target_network.initial_hidden(8, cpu_device)
                q_target_list = []
                q_values_list = []

                # First, unroll through entire sequence to get Q-values at each step
                for t in range(3):
                    q_values, target_hidden = target_network(batch["observations"][:, t, :], target_hidden)
                    q_values_list.append(q_values)

                # Now compute targets using the Q-values from next timestep
                for t in range(3):
                    if t < 2:
                        # Use Q-values from t+1 (already computed with hidden state from t)
                        q_next = q_values_list[t + 1].max(1)[0]
                        q_target = batch["rewards"][:, t] + gamma * q_next * (~batch["dones"][:, t]).float()
                    else:
                        # Terminal state
                        q_target = batch["rewards"][:, t]

                    q_target_list.append(q_target)

            # Compute loss with masking (P2.2)
            q_pred_all = torch.stack(q_pred_list, dim=1)
            q_target_all = torch.stack(q_target_list, dim=1)

            # Apply mask to prevent post-terminal gradients
            losses_raw = functional.mse_loss(q_pred_all, q_target_all, reduction="none")
            mask = batch["mask"].float()
            loss = (losses_raw * mask).sum() / mask.sum().clamp_min(1)

            # Backprop through time
            optimizer.zero_grad()
            loss.backward()
            torch.nn.utils.clip_grad_norm_(network.parameters(), max_norm=1.0)
            optimizer.step()

            # Update target network every 10 steps
            if iteration % 10 == 0:
                target_network.load_state_dict(network.state_dict())

            losses.append(loss.item())

        # Verify loss decreased (learning happened)
        initial_loss = sum(losses[:10]) / 10
        final_loss = sum(losses[-10:]) / 10

        assert (
            final_loss < initial_loss * 0.5
        ), f"Loss should decrease during training. Initial: {initial_loss:.4f}, Final: {final_loss:.4f}"

    def test_lstm_memory_persistence_in_training(self, cpu_device):
        """
        Test that LSTM hidden state persists across timesteps during sequence training.

        Migrated from test_lstm_temporal_learning.py::test_lstm_memory_persistence_in_training.

        This validates that the training loop correctly maintains hidden state
        when unrolling through sequences (as opposed to resetting each timestep).
        """
        network = RecurrentSpatialQNetwork(
            action_dim=2,
            window_size=1,
            position_dim=2,
            bars_dim=2,
            num_affordance_types=1,
            enable_temporal_features=False,
            hidden_dim=16,
        ).to(cpu_device)

        # Create a sequence of 3 observations
        obs_sequence = torch.randn(4, 3, 7)  # [batch=4, seq_len=3, obs_dim=7]

        # Fresh hidden state once for the batch, threaded through the unroll
        hidden = network.initial_hidden(4, cpu_device)

        # Unroll through sequence, tracking hidden states
        hidden_states = []

        for t in range(3):
            q_values, hidden = network(obs_sequence[:, t, :], hidden)
            h, c = hidden
            hidden_states.append((h.clone(), c.clone()))

        # Verify hidden state changed across timesteps
        h0, c0 = hidden_states[0]
        h1, c1 = hidden_states[1]
        h2, c2 = hidden_states[2]

        # Hidden states should be different (memory is evolving)
        assert not torch.allclose(h0, h1), "Hidden state should change between timesteps"
        assert not torch.allclose(h1, h2), "Hidden state should change between timesteps"

        # Cell states should also be different
        assert not torch.allclose(c0, c1), "Cell state should change between timesteps"
        assert not torch.allclose(c1, c2), "Cell state should change between timesteps"


# =============================================================================
# TEST CLASS 3: LSTM Forward Pass
# =============================================================================


class TestLSTMForwardPass:
    """Test LSTM forward pass with POMDP observations."""

    def test_partial_observability_5x5_window_to_lstm(self, cpu_device, cpu_env_factory):
        """
        Verify POMDP environment → LSTM data flow.

        POMDP env (vision_range=2) produces 5×5 window.
        LSTM forward pass should work correctly and produce Q-values.
        """
        env = cpu_env_factory(
            config_dir=Path("configs/default_curriculum"),
            num_agents=1,
            level_name="L2_partial_observability",
        )

        # Create recurrent network
        network = RecurrentSpatialQNetwork(
            action_dim=env.action_dim,
            window_size=5,
            position_dim=2,
            bars_dim=8,
            num_affordance_types=env.num_affordance_types,
            enable_temporal_features=False,
            hidden_dim=256,
        ).to(cpu_device)

        # Reset environment and get observation
        obs = env.reset()

        # Verify observation shape (POMDP)
        expected_obs_dim = env.metadata.observation_dim
        assert obs.shape == (1, expected_obs_dim), f"Expected obs shape (1, {expected_obs_dim}), got {obs.shape}"

        # Fresh hidden state
        initial_hidden = network.initial_hidden(1, cpu_device)

        # Forward pass
        q_values, new_hidden = network(obs, initial_hidden)

        # Verify Q-values shape
        assert q_values.shape == (1, env.action_dim), f"Expected Q-values shape (1, {env.action_dim}), got {q_values.shape}"

        # Verify hidden state shape
        h, c = new_hidden
        assert h.shape == (1, 1, 256), f"Expected h shape (1, 1, 256), got {h.shape}"
        assert c.shape == (1, 1, 256), f"Expected c shape (1, 1, 256), got {c.shape}"

        # Verify Q-values are finite
        assert torch.isfinite(q_values).all(), "Q-values should be finite"

        # Verify hidden state changed from initial zeros
        initial_h, initial_c = initial_hidden
        assert not torch.allclose(h, initial_h, atol=1e-6), "Hidden state should change after forward pass"
        assert not torch.allclose(c, initial_c, atol=1e-6), "Cell state should change after forward pass"
