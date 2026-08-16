"""Integration tests for multi-episode training loop execution.

This file tests multi-episode training with learning progression,
including masked loss enforcement and Q-value improvement.

Old files consolidated:
- test_masked_loss_integration.py (3 tests migrated to integration context)

Task 13b: Multi-Episode Training Loop Integration Tests
Focus: Test training loop over multiple episodes with real components
"""

import torch

from tests.test_townlet.helpers.config_builder import mutate_curriculum_yaml
from townlet.curriculum.static import StaticCurriculum
from townlet.exploration.epsilon_greedy import EpsilonGreedyExploration
from townlet.population.vectorized import VectorizedPopulation

# NOT `slow`-marked. This file runs in seconds; the marker (with the `-m "not slow"`
# that pyproject's default addopts USED to carry) is what hid its failures from
# every gate reading — see hamlet-a0832f9004.

# =============================================================================
# TEST CLASS 1: Masked Loss Integration
# =============================================================================


class TestMaskedLossIntegration:
    """Test masked loss during training with real components.

    These tests validate that masked loss is correctly applied during actual
    training with recurrent networks (LSTM). Masked loss prevents gradients
    from post-terminal garbage states in sequential replay.

    Migrated from test_masked_loss_integration.py, but now using real
    components instead of synthetic tensors.
    """

    def test_masked_loss_during_training(self, cpu_device, cpu_env_factory, config_pack_factory, recurrent_brain_config):
        """Verify masked loss computed correctly during LSTM training.

        This test validates the critical contract:
        - Masked loss = (losses * mask).sum() / mask.sum().clamp_min(1)
        - Mask prevents gradients from post-terminal timesteps
        - Loss is finite and training proceeds without NaN/Inf

        Integration point: VectorizedPopulation.step_population() with
        recurrent network applies masked loss during training.
        """

        def _modifier(cfg):
            # The modifier mutates training.yaml only; vision and temporal switches
            # live in curriculum.yaml and are set below.
            cfg["training"]["training_loop"]["max_steps_per_episode"] = 1000

        config_dir = config_pack_factory(modifier=_modifier, name="masked_loss")

        # POMDP: a 5-cell window on the 8×8 grid, matching L2_partial_observability.
        # vision_range is a FRACTION of the grid now, not a cell radius.
        mutate_curriculum_yaml(
            config_dir,
            lambda c: c["curriculum"].update({"active_vision": "partial", "vision_range": 0.5, "active_temporal": False}),
        )
        env = cpu_env_factory(config_dir=config_dir, num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = recurrent_brain_config

        # Create population with recurrent network
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,  # Random actions to prevent finding bed
            epsilon_min=1.0,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,  # LSTM for masked loss
            vision_window_size=5,
            batch_size=4,  # Small batch for fast test
            sequence_length=8,
            max_grad_norm=10.0,
            train_frequency=4,
        )

        # Reset and run multiple episodes to fill replay buffer
        # Note: Recurrent networks use SequentialReplayBuffer which stores EPISODES, not transitions
        # Episodes must complete (agent dies) to be flushed to buffer
        # With high depletion and random actions, agents should die quickly
        completed_episodes = 0
        for episode in range(30):  # More episodes to ensure some complete
            population.reset()
            for step in range(30):
                agent_state = population.step_population(env)
                if agent_state.dones[0]:
                    completed_episodes += 1
                    break

        # Verify at least some episodes completed
        assert completed_episodes > 0, f"Should have completed at least 1 episode, got {completed_episodes}"

        # Verify buffer has episodes (episodes are flushed when agents die)
        buffer_size = len(population.replay_buffer)
        # Buffer size should be > 0 since episodes completed
        # Note: SequentialReplayBuffer may have fewer episodes than completed if buffer is full
        assert buffer_size >= 0, f"Buffer size should be non-negative, got {buffer_size}"

        # Verify training has occurred (total_steps should be > 0 after episodes)
        assert population.total_steps > 0, "Should have accumulated training steps"

        # Verify training metrics are finite (masked loss should prevent NaN/Inf)
        # Only check if training actually occurred (buffer had enough episodes)
        if population.last_loss is not None:
            assert torch.isfinite(torch.tensor(population.last_loss)), f"Loss should be finite, got {population.last_loss}"
        if population.last_td_error is not None:
            assert torch.isfinite(torch.tensor(population.last_td_error)), f"TD error should be finite, got {population.last_td_error}"

    def test_action_masking_enforced_in_q_values(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify action masking enforced in Q-values during action selection.

        This test validates the critical contract:
        - Invalid actions (out of bounds, closed affordances) are masked
        - Masked actions have Q-values set to -inf before action selection
        - epsilon-greedy selection never picks masked actions

        Integration point: VectorizedPopulation.step_population() calls
        env.get_action_masks() and passes masks to exploration.select_actions().
        """
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create population
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,  # Full random to test masking thoroughly
            epsilon_min=1.0,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Reset and run steps
        population.reset()

        # Track actions over 50 steps
        actions_taken = []
        for step in range(50):
            agent_state = population.step_population(env)
            actions_taken.append(agent_state.actions[0].item())

            if agent_state.dones[0]:
                break

        # Verify actions are valid (should be in [0, action_dim))
        for action in actions_taken:
            assert 0 <= action < env.action_dim, f"Action should be in [0, {env.action_dim}), got {action}"

        # Verify actions were taken (not all zeros)
        assert len(set(actions_taken)) > 1, "Should have variety of actions (not all zeros)"

    def test_boundary_masking_during_training(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify boundary masking prevents out-of-bounds movement.

        This test validates the critical contract:
        - Agents near boundaries cannot move out of bounds
        - Action masking prevents UP at top edge, DOWN at bottom, etc.
        - Agents stay within grid boundaries during entire episode

        Integration point: VectorizedHamletEnv.get_action_masks() returns
        boundary masks, VectorizedPopulation enforces them during action selection.
        """
        # Create small environment to easily hit boundaries
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create population with random exploration to test boundaries
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,  # Full random to hit boundaries
            epsilon_min=1.0,
            epsilon_decay=1.0,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Reset and run steps
        population.reset()

        # Track positions over 100 steps (should hit boundaries)
        positions = []
        for step in range(100):
            agent_state = population.step_population(env)
            positions.append(env.positions[0].cpu().clone())

            if agent_state.dones[0]:
                break

        # Verify all positions are within bounds (8×8 grid from substrate.yaml)
        grid_size = 8  # Loaded from substrate.yaml, not from grid_size parameter
        for pos in positions:
            x, y = pos[0].item(), pos[1].item()
            assert 0 <= x < grid_size, f"X position should be in [0, {grid_size}), got {x}"
            assert 0 <= y < grid_size, f"Y position should be in [0, {grid_size}), got {y}"


# =============================================================================
# TEST CLASS 2: Multi-Episode Training
# =============================================================================


class TestMultiEpisodeTraining:
    """Test multi-episode training with learning progression.

    These tests validate that agents improve over multiple episodes through
    Q-learning, with proper epsilon decay, replay buffer accumulation, and
    target network updates.
    """

    def test_train_10_episodes_with_learning_progression(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify agents improve over 10 episodes (survival time or Q-values).

        This test validates the critical contract:
        - Agents should show learning progression over episodes
        - Q-network weights should change during training
        - Replay buffer should accumulate experiences
        - Epsilon should decay to encourage exploitation

        Integration point: Multi-episode loop with VectorizedPopulation.step_population()
        called repeatedly across episodes.
        """
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create population with epsilon decay
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,
            epsilon_min=0.1,
            epsilon_decay=0.95,  # Decay to 0.1 over ~20 episodes
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Capture initial Q-network weights
        initial_weights = {k: v.clone() for k, v in population.q_network.state_dict().items()}

        # Train for 10 episodes
        survival_times = []
        for episode in range(10):
            population.reset()
            episode_steps = 0

            for step in range(50):  # Max 50 steps per episode
                agent_state = population.step_population(env)
                episode_steps += 1

                if agent_state.dones[0]:
                    break

            survival_times.append(episode_steps)

            # Decay epsilon at episode end
            exploration.decay_epsilon()

        # Verify training occurred
        assert len(population.replay_buffer) > 0, "Replay buffer should have transitions"
        assert population.total_steps > 0, "Should have accumulated training steps"

        # Verify Q-network weights changed (learning occurred)
        final_weights = population.q_network.state_dict()
        weights_changed = False
        for key in initial_weights.keys():
            if not torch.allclose(initial_weights[key], final_weights[key], atol=1e-6):
                weights_changed = True
                break

        assert weights_changed, "Q-network weights should change during training"

        # Verify episodes completed
        assert len(survival_times) == 10, "Should complete 10 episodes"

    def test_epsilon_decay_over_episodes(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify epsilon decreases over episodes according to decay schedule.

        This test validates the critical contract:
        - Epsilon should start at epsilon_start (1.0)
        - Epsilon should decay by epsilon_decay per episode (0.95)
        - Epsilon should respect epsilon_min floor (0.1)
        - Epsilon decay should be called explicitly after each episode

        Integration point: EpsilonGreedyExploration.decay_epsilon() called
        by training loop after each episode.
        """
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create exploration with known decay parameters
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,
            epsilon_min=0.1,
            epsilon_decay=0.9,  # 10% decay per episode
        )

        curriculum = StaticCurriculum(difficulty_level=0.5)
        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Track epsilon over 20 episodes
        epsilon_history = []
        for episode in range(20):
            epsilon_history.append(exploration.epsilon)

            # Run short episode
            population.reset()
            for step in range(10):
                agent_state = population.step_population(env)
                if agent_state.dones[0]:
                    break

            # Decay epsilon at episode end
            exploration.decay_epsilon()

        # Verify epsilon decreased
        assert epsilon_history[0] == 1.0, "Initial epsilon should be 1.0"
        assert epsilon_history[-1] < epsilon_history[0], "Epsilon should decrease over episodes"

        # Verify epsilon respects minimum
        final_epsilon = exploration.epsilon
        assert final_epsilon >= 0.1, f"Epsilon should not go below min (0.1), got {final_epsilon}"

        # Verify approximate exponential decay (epsilon_10 ≈ 1.0 * 0.9^10 = 0.349)
        # After 20 episodes: epsilon ≈ 1.0 * 0.9^20 = 0.122 (clamped to 0.1)
        expected_epsilon_10 = 1.0 * (0.9**10)
        assert (
            abs(epsilon_history[10] - expected_epsilon_10) < 0.05
        ), f"Epsilon at episode 10 should be ~{expected_epsilon_10}, got {epsilon_history[10]}"

    def test_replay_buffer_accumulation_during_training(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify replay buffer accumulates transitions during training.

        This test validates the critical contract:
        - Buffer should start empty
        - Buffer should accumulate transitions during episode steps
        - Buffer size should increase monotonically (until capacity)
        - Buffer should store correct number of transitions

        Integration point: VectorizedPopulation.step_population() pushes
        transitions to replay buffer after each step.
        """
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create population
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(epsilon=0.1, epsilon_min=0.1, epsilon_decay=1.0)

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Verify buffer starts empty
        assert len(population.replay_buffer) == 0, "Replay buffer should start empty"

        # Run 5 episodes and track buffer size
        buffer_sizes = []
        for episode in range(5):
            population.reset()

            for step in range(20):
                agent_state = population.step_population(env)
                if agent_state.dones[0]:
                    break

            buffer_sizes.append(len(population.replay_buffer))

        # Verify buffer accumulated transitions
        assert buffer_sizes[-1] > 0, "Buffer should have transitions after training"

        # Verify buffer size increased (or stayed at capacity)
        for i in range(1, len(buffer_sizes)):
            assert (
                buffer_sizes[i] >= buffer_sizes[i - 1] or buffer_sizes[i] == 500
            ), f"Buffer size should increase or stay at capacity: {buffer_sizes}"

    def test_target_network_updates_at_frequency(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify target network updated at specified frequency.

        This test validates the critical contract:
        - Target network should start with same weights as Q-network
        - Target network should update every target_update_frequency training steps
        - Target network should sync with Q-network weights after update

        Integration point: VectorizedPopulation.step_population() updates
        target network every target_update_frequency training steps.
        """
        env = cpu_env_factory(num_agents=1)

        # Target-network cadence is authored in the brain config, not passed to the
        # constructor — VectorizedPopulation reads
        # brain_config.q_learning.target_update_frequency.
        brain_cfg = minimal_brain_config
        brain_cfg.q_learning.target_update_frequency = 10

        # Create population with short target update frequency
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(epsilon=0.1, epsilon_min=0.1, epsilon_decay=1.0)

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Capture initial target network weights
        initial_target_weights = {k: v.clone() for k, v in population.target_network.state_dict().items()}

        # Run training for enough steps to trigger target update
        # train_frequency=4, so training happens every 4 steps
        # target_update_frequency=10, so update happens after 10 training steps
        # Need at least 4 * 10 = 40 environment steps to trigger 10 training steps
        population.reset()
        for step in range(100):
            agent_state = population.step_population(env)
            if agent_state.dones[0]:
                population.reset()

        # Verify training occurred
        assert population.training_step_counter > 0, "Should have training steps"

        # Verify target network updated (weights changed)
        final_target_weights = population.target_network.state_dict()
        target_weights_changed = False
        for key in initial_target_weights.keys():
            if not torch.allclose(initial_target_weights[key], final_target_weights[key], atol=1e-6):
                target_weights_changed = True
                break

        # If enough training steps occurred, target network should have updated
        if population.training_step_counter >= 10:
            assert target_weights_changed, f"Target network should update after {population.training_step_counter} training steps"

    def test_q_values_improve_over_time(self, cpu_device, cpu_env_factory, minimal_brain_config):
        """Verify Q-values become more certain over time (reduced variance).

        This test validates the critical contract:
        - Early Q-values should be random (high variance)
        - Later Q-values should be more certain (lower variance, higher magnitude)
        - Q-network should learn to predict survival better over episodes

        Integration point: VectorizedPopulation.step_population() trains
        Q-network, causing Q-values to become more certain over time.
        """
        env = cpu_env_factory(num_agents=1)

        # Brain config loaded from fixture
        brain_cfg = minimal_brain_config

        # Create population
        curriculum = StaticCurriculum(difficulty_level=0.5)
        exploration = EpsilonGreedyExploration(
            epsilon=1.0,
            epsilon_min=0.1,
            epsilon_decay=0.95,
        )

        population = VectorizedPopulation(
            env=env,
            curriculum=curriculum,
            exploration=exploration,
            agent_ids=["agent_0"],
            device=cpu_device,
            obs_dim=env.observation_dim,
            action_dim=env.action_dim,
            brain_config=brain_cfg,
            batch_size=16,
            sequence_length=1,
            max_grad_norm=10.0,
            vision_window_size=5,
            train_frequency=4,
        )

        # Sample Q-values at episode 0 (untrained)
        population.reset()
        with torch.no_grad():
            q_values_initial = population.q_network(population.current_obs)
            initial_mean = q_values_initial.mean().item()
            initial_std = q_values_initial.std().item()

        # Train for 20 episodes
        for episode in range(20):
            population.reset()

            for step in range(30):
                agent_state = population.step_population(env)
                if agent_state.dones[0]:
                    break

            exploration.decay_epsilon()

        # Sample Q-values at episode 20 (trained)
        population.reset()
        with torch.no_grad():
            q_values_final = population.q_network(population.current_obs)
            final_mean = q_values_final.mean().item()
            final_std = q_values_final.std().item()

        # Verify Q-values changed (learning occurred)
        # Note: We can't assert exact improvement due to randomness,
        # but Q-values should be different after training
        assert abs(final_mean - initial_mean) > 0.01 or abs(final_std - initial_std) > 0.01, "Q-values should change after training"

        # Verify training metrics were updated
        assert population.last_q_values_mean is not None, "Should have Q-value metrics"
        assert population.last_loss is not None, "Should have loss metrics"
