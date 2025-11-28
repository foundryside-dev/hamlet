"""Property-based tests for ReplayBuffer.

These tests use Hypothesis to verify universal properties of the replay buffer
that should hold for all possible sequences of operations.

Properties tested:
1. Buffer size never exceeds capacity (FIFO eviction)
2. Sampled batches always have correct shapes and types
3. Reward combination is always computed correctly
4. Buffer handles any push/sample sequence without crashing
"""

import torch
from hypothesis import assume, given, settings
from hypothesis import strategies as st

from townlet.training.replay_buffer import ReplayBuffer
from townlet.training.state import RewardTensor


class TestReplayBufferCapacityProperties:
    """Property tests for buffer capacity and FIFO behavior."""

    @given(
        capacity=st.integers(min_value=10, max_value=1000),
        num_pushes=st.integers(min_value=1, max_value=2000),
        batch_size=st.integers(min_value=1, max_value=10),
    )
    @settings(max_examples=50)
    def test_buffer_never_exceeds_capacity(self, capacity, num_pushes, batch_size):
        """Property: Buffer size never exceeds capacity, regardless of push count.

        The buffer should implement FIFO eviction such that len(buffer) <= capacity
        always holds true, even after pushing far more transitions than capacity.
        """
        buffer = ReplayBuffer(capacity=capacity, device=torch.device("cpu"))

        obs_dim = 5

        # Push num_pushes transitions in batches
        pushes_done = 0
        while pushes_done < num_pushes:
            current_batch = min(batch_size, num_pushes - pushes_done)

            obs = torch.randn(current_batch, obs_dim)
            actions = torch.randint(0, 6, (current_batch,))
            rewards = RewardTensor.from_components(extrinsic=torch.randn(current_batch), intrinsic=torch.randn(current_batch))
            next_obs = torch.randn(current_batch, obs_dim)
            dones = torch.rand(current_batch) > 0.8

            buffer.push(obs, actions, rewards, next_obs, dones)
            pushes_done += current_batch

            # PROPERTY: Buffer size never exceeds capacity
            assert len(buffer) <= capacity, f"Buffer size {len(buffer)} exceeds capacity {capacity}"

        # PROPERTY: After many pushes, buffer should be at capacity
        if num_pushes >= capacity:
            assert len(buffer) == capacity

    @given(
        capacity=st.integers(min_value=10, max_value=100),
        num_pushes=st.integers(min_value=100, max_value=200),
    )
    @settings(max_examples=30)
    def test_fifo_eviction_behavior(self, capacity, num_pushes):
        """Property: Oldest data is evicted when buffer is full (FIFO).

        After pushing more than capacity transitions, the buffer should contain
        only the most recent 'capacity' transitions.
        """
        assume(num_pushes > capacity)

        buffer = ReplayBuffer(capacity=capacity, device=torch.device("cpu"))

        obs_dim = 3

        # Push transitions one at a time, marking each with a unique ID
        for i in range(num_pushes):
            # Use observation value to track insertion order
            obs = torch.full((1, obs_dim), float(i))
            actions = torch.tensor([0])
            rewards = RewardTensor.from_components(extrinsic=torch.tensor([0.0]), intrinsic=torch.tensor([0.0]))
            next_obs = torch.zeros(1, obs_dim)
            dones = torch.tensor([False])

            buffer.push(obs, actions, rewards, next_obs, dones)

        # PROPERTY: Buffer contains only the last 'capacity' transitions
        assert len(buffer) == capacity

        # Sample all transitions to verify they are the most recent
        assert buffer.observations is not None
        stored_observations = buffer.observations[: buffer.size]

        # The stored IDs should be [num_pushes - capacity, ..., num_pushes - 1]
        min_expected_id = num_pushes - capacity
        max_expected_id = num_pushes - 1

        # Extract IDs from observations
        stored_ids = stored_observations[:, 0]  # First dimension stores the ID

        # PROPERTY: All stored IDs are in the expected range (most recent)
        assert torch.all(stored_ids >= min_expected_id), f"Found ID {stored_ids.min()} < {min_expected_id}"
        assert torch.all(stored_ids <= max_expected_id), f"Found ID {stored_ids.max()} > {max_expected_id}"


class TestReplayBufferSamplingProperties:
    """Property tests for buffer sampling behavior."""

    @given(
        capacity=st.integers(min_value=20, max_value=200),
        fill_amount=st.integers(min_value=20, max_value=200),
        sample_batch_size=st.integers(min_value=1, max_value=32),
    )
    @settings(max_examples=50)
    def test_sampled_batches_have_correct_shapes(self, capacity, fill_amount, sample_batch_size):
        """Property: Sampled batches always have correct shapes and dtypes.

        Regardless of buffer state, samples should always have:
        - observations: [batch_size, obs_dim]
        - actions: [batch_size] (long)
        - rewards: [batch_size] (float)
        - next_observations: [batch_size, obs_dim]
        - dones: [batch_size] (bool)
        """
        # Only sample if buffer has enough data
        # Buffer can't hold more than capacity, so effective fill is min(fill_amount, capacity)
        effective_fill = min(fill_amount, capacity)
        assume(effective_fill >= sample_batch_size)

        buffer = ReplayBuffer(capacity=capacity, device=torch.device("cpu"))

        obs_dim = 7

        # Fill buffer to effective_fill amount
        transitions_pushed = 0
        while transitions_pushed < effective_fill:
            batch = min(10, effective_fill - transitions_pushed)
            obs = torch.randn(batch, obs_dim)
            actions = torch.randint(0, 6, (batch,))
            rewards = RewardTensor.from_components(extrinsic=torch.randn(batch), intrinsic=torch.randn(batch))
            next_obs = torch.randn(batch, obs_dim)
            dones = torch.rand(batch) > 0.9

            buffer.push(obs, actions, rewards, next_obs, dones)
            transitions_pushed += batch

        # Sample batch
        batch = buffer.sample(batch_size=sample_batch_size)

        # PROPERTY: Correct shapes
        assert batch["observations"].shape == (sample_batch_size, obs_dim)
        assert batch["actions"].shape == (sample_batch_size,)
        assert batch["rewards"].shape == (sample_batch_size,)
        assert batch["next_observations"].shape == (sample_batch_size, obs_dim)
        assert batch["dones"].shape == (sample_batch_size,)
        assert batch["mask"].shape == (sample_batch_size,)

        # PROPERTY: Correct dtypes
        assert batch["observations"].dtype == torch.float32
        assert batch["actions"].dtype == torch.long
        assert batch["rewards"].dtype == torch.float32
        assert batch["next_observations"].dtype == torch.float32
        assert batch["dones"].dtype == torch.bool
        assert batch["mask"].dtype == torch.bool

    @given(
        intrinsic_weight=st.floats(min_value=0.0, max_value=10.0),
    )
    @settings(max_examples=30)
    def test_reward_combination_is_correct(self, intrinsic_weight):
        """Property: RewardTensor correctly computes total from components.

        The RewardTensor DTO should correctly combine extrinsic and intrinsic rewards
        using the provided weight, for any valid weight value.
        """
        buffer = ReplayBuffer(capacity=100, device=torch.device("cpu"))

        # Push transitions with known reward values
        num_transitions = 50
        obs_dim = 4

        # Use known reward values for verification
        extrinsic_values = torch.arange(num_transitions, dtype=torch.float32)  # [0, 1, 2, ..., 49]
        intrinsic_values = torch.ones(num_transitions) * 2.0  # All 2.0

        obs = torch.randn(num_transitions, obs_dim)
        actions = torch.zeros(num_transitions, dtype=torch.long)
        next_obs = torch.randn(num_transitions, obs_dim)
        dones = torch.zeros(num_transitions, dtype=torch.bool)

        # CRIT-07: Compute rewards using RewardTensor
        rewards = RewardTensor.from_components(extrinsic=extrinsic_values, intrinsic=intrinsic_values, intrinsic_weight=intrinsic_weight)

        buffer.push(obs, actions, rewards, next_obs, dones)

        # Sample all transitions
        batch = buffer.sample(batch_size=num_transitions)

        # Compute expected rewards for verification
        # Since we know extrinsic ∈ [0, 49] and intrinsic = 2.0
        # Combined should be in [0 + 2*w, 49 + 2*w]
        expected_min = 0.0 + 2.0 * intrinsic_weight
        expected_max = 49.0 + 2.0 * intrinsic_weight

        # PROPERTY: All rewards are in expected range
        sampled_rewards = batch["rewards"]
        assert torch.all(sampled_rewards >= expected_min - 1e-5), f"Reward {sampled_rewards.min()} < {expected_min}"
        assert torch.all(sampled_rewards <= expected_max + 1e-5), f"Reward {sampled_rewards.max()} > {expected_max}"

    @given(
        push_sample_sequence=st.lists(
            st.tuples(st.just("push"), st.integers(min_value=1, max_value=10))
            | st.tuples(st.just("sample"), st.integers(min_value=1, max_value=8)),
            min_size=1,
            max_size=20,
        )
    )
    @settings(max_examples=30)
    def test_buffer_handles_interleaved_push_and_sample(self, push_sample_sequence):
        """Property: Buffer handles any sequence of push/sample operations.

        The buffer should gracefully handle any interleaving of push and sample
        operations without crashing or corrupting state.
        """
        buffer = ReplayBuffer(capacity=100, device=torch.device("cpu"))
        obs_dim = 6

        for operation, count in push_sample_sequence:
            if operation == "push":
                # Push transitions
                obs = torch.randn(count, obs_dim)
                actions = torch.randint(0, 6, (count,))
                rewards = RewardTensor.from_components(extrinsic=torch.randn(count), intrinsic=torch.randn(count))
                next_obs = torch.randn(count, obs_dim)
                dones = torch.rand(count) > 0.9

                buffer.push(obs, actions, rewards, next_obs, dones)

                # PROPERTY: Buffer size is valid after push
                assert len(buffer) <= buffer.capacity

            elif operation == "sample":
                # Only sample if buffer has enough data
                if len(buffer) >= count:
                    batch = buffer.sample(batch_size=count)

                    # PROPERTY: Sampled batch has correct size
                    assert batch["observations"].shape[0] == count
                    assert batch["actions"].shape[0] == count
                    assert batch["rewards"].shape[0] == count

        # PROPERTY: Buffer state is consistent after all operations
        assert len(buffer) <= buffer.capacity
        assert buffer.position >= 0
        assert buffer.size >= 0


class TestReplayBufferSerializationProperties:
    """Property tests for buffer serialization/deserialization."""

    @given(
        capacity=st.integers(min_value=10, max_value=100),
        num_transitions=st.integers(min_value=5, max_value=100),
    )
    @settings(max_examples=30)
    def test_serialize_deserialize_roundtrip(self, capacity, num_transitions):
        """Property: serialize → deserialize is identity (preserves buffer state).

        After serializing and deserializing, the buffer should contain exactly
        the same data in the same order.
        """
        buffer = ReplayBuffer(capacity=capacity, device=torch.device("cpu"))
        obs_dim = 5

        # Fill buffer with known data
        num_to_push = min(num_transitions, capacity)
        obs = torch.randn(num_to_push, obs_dim)
        actions = torch.randint(0, 6, (num_to_push,))
        rewards = RewardTensor.from_components(extrinsic=torch.randn(num_to_push), intrinsic=torch.randn(num_to_push))
        next_obs = torch.randn(num_to_push, obs_dim)
        dones = torch.rand(num_to_push) > 0.8

        buffer.push(obs, actions, rewards, next_obs, dones)

        # Serialize
        state = buffer.serialize()

        # Create new buffer and deserialize
        new_buffer = ReplayBuffer(capacity=capacity, device=torch.device("cpu"))
        new_buffer.load_from_serialized(state)

        # PROPERTY: Buffer size is preserved
        assert len(new_buffer) == len(buffer)
        # After deserialization, position is restored from serialized state (which was reset to size)
        assert new_buffer.position == state["position"]

        # PROPERTY: Data is identical
        if buffer.observations is not None:
            assert new_buffer.observations is not None
            assert torch.allclose(new_buffer.observations[: new_buffer.size], buffer.observations[: buffer.size])
            assert torch.equal(new_buffer.actions[: new_buffer.size], buffer.actions[: buffer.size])
            assert torch.allclose(new_buffer.rewards[: new_buffer.size], buffer.rewards[: buffer.size])
