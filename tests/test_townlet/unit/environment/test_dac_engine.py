"""Tests for DAC Engine."""

import pytest
import torch

from townlet.config.drive_as_code import (
    BarBonusConfig,
    DriveAsCodeConfig,
    ExtrinsicStrategyConfig,
    IntrinsicStrategyConfig,
    ModifierConfig,
    RangeConfig,
    VariableBonusConfig,
)
from townlet.environment.dac_engine import DACEngine
from townlet.vfs.registry import VariableRegistry
from townlet.vfs.schema import VariableDef


@pytest.fixture
def bar_index_map_single():
    """Standard bar index map for single-bar tests (energy only)."""
    return {"energy": 0}


@pytest.fixture
def bar_index_map_dual():
    """Standard bar index map for dual-bar tests (energy and health)."""
    return {"energy": 0, "health": 1}


class TestDACEngineInit:
    """Test DACEngine initialization."""

    def test_dac_engine_initializes(self, bar_index_map_single):
        """DACEngine initializes with minimal config."""
        device = torch.device("cpu")
        num_agents = 4

        # Create minimal VFS registry
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Create minimal DAC config
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="none",
                base_weight=0.0,
            ),
        )

        # Initialize engine
        engine = DACEngine(
            dac_config=dac_config,
            vfs_registry=vfs_registry,
            device=device,
            num_agents=num_agents,
            bar_index_map=bar_index_map_single,
        )

        assert engine is not None
        assert engine.device == device
        assert engine.num_agents == num_agents

    def test_get_bar_index_missing_bar_raises(self):
        """_get_bar_index raises KeyError for undefined bar."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Config references "health" bar, but bar_index_map only has "energy"
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],  # health not in bar_index_map
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="none",
                base_weight=0.0,
            ),
        )

        bar_index_map = {"energy": 0}  # Only energy defined
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map)

        # Create dummy meters
        meters = torch.tensor([[1.0], [0.8], [0.5], [0.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        # Trying to compute extrinsic with undefined bar should raise
        with pytest.raises(KeyError, match="Bar 'health' not found in universe metadata"):
            engine.extrinsic_fn(meters, dones)


class TestModifierCompilation:
    """Test modifier compilation and evaluation."""

    def test_compile_bar_modifier(self, bar_index_map_single):
        """Modifier with bar source compiles correctly."""
        device = torch.device("cpu")
        num_agents = 4

        # Minimal VFS
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # DAC with energy crisis modifier
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "energy_crisis": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="crisis", min=0.0, max=0.3, multiplier=0.0),
                        RangeConfig(name="normal", min=0.3, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", base=1.0, bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Verify modifier was compiled
        assert "energy_crisis" in engine.modifiers
        assert callable(engine.modifiers["energy_crisis"])

    def test_evaluate_bar_modifier_crisis_range(self, bar_index_map_single):
        """Bar modifier returns correct multiplier for crisis range."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "energy_crisis": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="crisis", min=0.0, max=0.3, multiplier=0.0),
                        RangeConfig(name="normal", min=0.3, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", base=1.0, bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Create meter values with 2 agents in crisis (< 0.3), 2 normal (>= 0.3)
        meters = torch.tensor([[0.1], [0.2], [0.5], [0.8]], device=device)  # [4, 1] energy only

        # Evaluate modifier
        multipliers = engine.modifiers["energy_crisis"](meters)

        # Should return 0.0 for crisis agents, 1.0 for normal agents
        expected = torch.tensor([0.0, 0.0, 1.0, 1.0], device=device)
        assert torch.allclose(multipliers, expected)

    def test_evaluate_bar_modifier_normal_range(self, bar_index_map_single):
        """Bar modifier returns correct multiplier for normal range."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "energy_crisis": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="crisis", min=0.0, max=0.3, multiplier=0.0),
                        RangeConfig(name="normal", min=0.3, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", base=1.0, bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # All agents in normal range
        meters = torch.tensor([[0.4], [0.6], [0.8], [1.0]], device=device)

        multipliers = engine.modifiers["energy_crisis"](meters)

        # All should return 1.0
        expected = torch.ones(num_agents, device=device)
        assert torch.allclose(multipliers, expected)

    def test_compile_vfs_variable_modifier(self, bar_index_map_dual):
        """Modifier with VFS variable source compiles correctly."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="social_score",
                    scope="agent",
                    type="scalar",
                    default=0.5,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "social_boost": ModifierConfig(
                    variable="social_score",  # VFS variable, not bar
                    ranges=[
                        RangeConfig(name="low", min=0.0, max=0.5, multiplier=0.5),
                        RangeConfig(name="high", min=0.5, max=1.0, multiplier=1.5),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", base=1.0, bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        assert "social_boost" in engine.modifiers
        assert callable(engine.modifiers["social_boost"])

    def test_vfs_modifier_missing_variable_raises_with_context(self, bar_index_map_single):
        """Modifier referencing missing VFS variable raises KeyError with context (ENV-004).

        The error message should include:
        1. The missing variable name
        2. The modifier name that references it
        3. Available variables in registry
        """
        device = torch.device("cpu")
        num_agents = 4

        # Create VFS registry with only 'energy' variable
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Config referencing non-existent VFS variable in modifier
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "missing_var_modifier": ModifierConfig(
                    variable="nonexistent_social_score",  # This variable doesn't exist
                    ranges=[
                        RangeConfig(name="low", min=0.0, max=0.5, multiplier=0.5),
                        RangeConfig(name="high", min=0.5, max=1.0, multiplier=1.5),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", base=1.0, bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Create dummy meters
        meters = torch.tensor([[1.0], [0.8], [0.5], [0.0]], device=device)

        # Evaluate modifier - should raise KeyError with context
        with pytest.raises(KeyError) as excinfo:
            engine.modifiers["missing_var_modifier"](meters)

        error_msg = str(excinfo.value)
        # Error should contain the missing variable name
        assert "nonexistent_social_score" in error_msg
        # Error should contain the modifier name
        assert "missing_var_modifier" in error_msg
        # Error should mention available variables
        assert "Available" in error_msg or "available" in error_msg


class TestExtrinsicStrategies:
    """Test extrinsic reward strategy compilation."""

    def test_multiplicative_strategy(self, bar_index_map_single):
        """Multiplicative strategy: reward = base * bar1 * bar2 * ..."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=2.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Create meter values: [0.5, 0.8, 1.0, 0.0]
        meters = torch.tensor([[0.5], [0.8], [1.0], [0.0]], device=device)
        dones = torch.tensor([False, False, False, True], device=device)

        # Calculate extrinsic rewards
        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base * energy (2.0 * [0.5, 0.8, 1.0, 0.0])
        # Dead agents get 0.0
        expected = torch.tensor([1.0, 1.6, 2.0, 0.0], device=device)
        assert torch.allclose(extrinsic, expected)

    def test_multiplicative_multiple_bars(self, bar_index_map_dual):
        """Multiplicative with multiple bars: reward = base * energy * health"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.5, 0.8], [1.0, 1.0], [0.2, 0.5], [0.0, 1.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: 1.0 * energy * health
        expected = torch.tensor([0.4, 1.0, 0.1, 0.0], device=device)
        assert torch.allclose(extrinsic, expected, atol=1e-6)

    def test_constant_base_with_shaped_bonus(self, bar_index_map_dual):
        """Constant base + shaped bonus: reward = base + sum(bonuses)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="constant_base_with_shaped_bonus",
                base_reward=1.0,
                bars=["energy"],  # Define meter ordering
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.5, scale=0.5),
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Energy values: [0.0, 0.5, 1.0, 0.25]
        meters = torch.tensor([[0.0], [0.5], [1.0], [0.25]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base_reward + scale * (energy - center)
        # [1.0 + 0.5 * (0.0 - 0.5), 1.0 + 0.5 * (0.5 - 0.5), 1.0 + 0.5 * (1.0 - 0.5), 1.0 + 0.5 * (0.25 - 0.5)]
        # = [0.75, 1.0, 1.25, 0.875]
        expected = torch.tensor([0.75, 1.0, 1.25, 0.875], device=device)
        assert torch.allclose(extrinsic, expected)

    def test_constant_base_multiple_bonuses(self, bar_index_map_dual):
        """Constant base with multiple bar bonuses and variable bonus"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                ),
                VariableDef(
                    id="custom_score",
                    scope="agent",
                    type="scalar",
                    default=0.5,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        # Set custom_score values
        vfs_registry.set("custom_score", torch.tensor([0.1, 0.2, 0.3, 0.4], device=device), writer="engine")

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="constant_base_with_shaped_bonus",
                base_reward=2.0,
                bars=["energy", "health"],  # Define meter ordering
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.5, scale=0.5),
                    BarBonusConfig(bar="health", center=0.5, scale=0.3),
                ],
                variable_bonuses=[
                    VariableBonusConfig(variable="custom_score", weight=2.0),
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.5, 0.5], [0.8, 0.6], [0.2, 0.4], [1.0, 1.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base_reward + energy_bonus + health_bonus + custom_score * 2.0
        # For agent 0: 2.0 + 0.5*(0.5-0.5) + 0.3*(0.5-0.5) + 2.0*0.1 = 2.0 + 0 + 0 + 0.2 = 2.2
        # For agent 1: 2.0 + 0.5*(0.8-0.5) + 0.3*(0.6-0.5) + 2.0*0.2 = 2.0 + 0.15 + 0.03 + 0.4 = 2.58
        # For agent 2: 2.0 + 0.5*(0.2-0.5) + 0.3*(0.4-0.5) + 2.0*0.3 = 2.0 - 0.15 - 0.03 + 0.6 = 2.42
        # For agent 3: 2.0 + 0.5*(1.0-0.5) + 0.3*(1.0-0.5) + 2.0*0.4 = 2.0 + 0.25 + 0.15 + 0.8 = 3.2
        expected = torch.tensor([2.2, 2.58, 2.42, 3.2], device=device)
        assert torch.allclose(extrinsic, expected, atol=1e-6)

    def test_additive_unweighted_strategy(self, bar_index_map_dual):
        """Additive unweighted: reward = base + sum(bars)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="additive_unweighted",
                base=0.5,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.2, 0.3], [0.5, 0.5], [0.8, 0.9], [0.0, 0.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base + energy + health
        # [0.5 + 0.2 + 0.3, 0.5 + 0.5 + 0.5, 0.5 + 0.8 + 0.9, 0.5 + 0.0 + 0.0]
        expected = torch.tensor([1.0, 1.5, 2.2, 0.5], device=device)
        assert torch.allclose(extrinsic, expected, atol=1e-6)

    def test_weighted_sum_strategy(self, bar_index_map_dual):
        """Weighted sum: reward = sum(weight_i * source_i)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # For this test, assume weighted_sum uses bar_bonuses with weights
        # (simplified version without sources field for now)
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="weighted_sum",
                base=0.0,
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.0, scale=2.0),  # weight=2.0
                    BarBonusConfig(bar="health", center=0.0, scale=1.5),  # weight=1.5
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.5, 0.4], [1.0, 1.0], [0.2, 0.8], [0.0, 0.5]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: 2.0 * energy + 1.5 * health
        # [2.0*0.5 + 1.5*0.4, 2.0*1.0 + 1.5*1.0, 2.0*0.2 + 1.5*0.8, 2.0*0.0 + 1.5*0.5]
        expected = torch.tensor([1.6, 3.5, 1.6, 0.75], device=device)
        assert torch.allclose(extrinsic, expected, atol=1e-6)

    def test_polynomial_strategy(self, bar_index_map_dual):
        """Polynomial: reward = sum(weight_i * bar_i^exponent_i)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Using bar_bonuses: scale=weight, center=exponent
        # Note: center must be in [0.0, 1.0] due to BarBonusConfig constraints
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="polynomial",
                base=0.0,
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.5, scale=2.0),  # 2.0 * energy^0.5
                    BarBonusConfig(bar="health", center=1.0, scale=1.5),  # 1.5 * health^1.0
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.25, 0.4], [1.0, 1.0], [0.64, 0.9], [0.0, 0.5]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: 2.0 * energy^0.5 + 1.5 * health^1.0
        # [2.0*0.5 + 1.5*0.4, 2.0*1.0 + 1.5*1.0, 2.0*0.8 + 1.5*0.9, 2.0*0.0 + 1.5*0.5]
        expected = torch.tensor(
            [
                2.0 * 0.25**0.5 + 1.5 * 0.4**1.0,
                2.0 * 1.0**0.5 + 1.5 * 1.0**1.0,
                2.0 * 0.64**0.5 + 1.5 * 0.9**1.0,
                2.0 * 0.0**0.5 + 1.5 * 0.5**1.0,
            ],
            device=device,
        )
        assert torch.allclose(extrinsic, expected, atol=1e-4)

    def test_all_strategies_handle_dead_agents(self, bar_index_map_single):
        """All extrinsic strategies return 0.0 for dead agents."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Test multiplicative strategy
        dac_multiplicative = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=2.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )
        engine = DACEngine(dac_multiplicative, vfs_registry, device, num_agents, bar_index_map_single)

        # Agents 0,1 alive with high energy, agents 2,3 dead with high energy
        meters = torch.tensor([[1.0], [0.8], [1.0], [0.9]], device=device)
        dones = torch.tensor([False, False, True, True], device=device)
        rewards = engine.extrinsic_fn(meters, dones)

        # Alive agents get rewards, dead agents get 0.0
        assert rewards[0] > 0.0  # Alive agent with energy=1.0
        assert rewards[1] > 0.0  # Alive agent with energy=0.8
        assert rewards[2] == 0.0  # Dead agent (should be 0.0 despite energy=1.0)
        assert rewards[3] == 0.0  # Dead agent (should be 0.0 despite energy=0.9)

        # Test constant_base_with_shaped_bonus strategy
        dac_constant = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="constant_base_with_shaped_bonus",
                base_reward=1.0,
                bar_bonuses=[BarBonusConfig(bar="energy", center=0.5, scale=0.5)],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )
        engine = DACEngine(dac_constant, vfs_registry, device, num_agents, bar_index_map_single)
        rewards = engine.extrinsic_fn(meters, dones)

        assert rewards[0] > 0.0
        assert rewards[1] > 0.0
        assert rewards[2] == 0.0
        assert rewards[3] == 0.0

        # Test additive_unweighted strategy
        dac_additive = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="additive_unweighted",
                base=0.5,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )
        engine = DACEngine(dac_additive, vfs_registry, device, num_agents, bar_index_map_single)
        rewards = engine.extrinsic_fn(meters, dones)

        assert rewards[0] > 0.0
        assert rewards[1] > 0.0
        assert rewards[2] == 0.0
        assert rewards[3] == 0.0

        # Test weighted_sum strategy
        dac_weighted = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="weighted_sum",
                base=0.0,
                bar_bonuses=[BarBonusConfig(bar="energy", center=0.0, scale=2.0)],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )
        engine = DACEngine(dac_weighted, vfs_registry, device, num_agents, bar_index_map_single)
        rewards = engine.extrinsic_fn(meters, dones)

        assert rewards[0] > 0.0
        assert rewards[1] > 0.0
        assert rewards[2] == 0.0
        assert rewards[3] == 0.0

        # Test polynomial strategy
        dac_polynomial = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="polynomial",
                base=0.0,
                bar_bonuses=[BarBonusConfig(bar="energy", center=0.5, scale=2.0)],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )
        engine = DACEngine(dac_polynomial, vfs_registry, device, num_agents, bar_index_map_single)
        rewards = engine.extrinsic_fn(meters, dones)

        assert rewards[0] > 0.0
        assert rewards[1] > 0.0
        assert rewards[2] == 0.0
        assert rewards[3] == 0.0

    def test_threshold_based_strategy(self, bar_index_map_dual):
        """Threshold-based: bonus when bar crosses threshold"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Threshold at 0.5: give bonus=1.0 if energy >= 0.5, else bonus=0.0
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="threshold_based",
                base=0.5,
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.5, scale=1.0),  # threshold=0.5, bonus=1.0
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Energy values: [0.2, 0.5, 0.8, 1.0]
        meters = torch.tensor([[0.2], [0.5], [0.8], [1.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base + (1.0 if energy >= 0.5 else 0.0)
        # [0.5 + 0.0, 0.5 + 1.0, 0.5 + 1.0, 0.5 + 1.0]
        expected = torch.tensor([0.5, 1.5, 1.5, 1.5], device=device)
        assert torch.allclose(extrinsic, expected)

    def test_aggregation_min_strategy(self, bar_index_map_dual):
        """Aggregation (min): reward = base + min(bars)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # For this simplified version, assume aggregation always uses min()
        # A more complete implementation would have an 'operation' field
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="aggregation",
                base=0.5,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.3, 0.8], [0.5, 0.4], [0.9, 0.7], [0.2, 0.1]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base + min(energy, health)
        # [0.5 + min(0.3, 0.8), 0.5 + min(0.5, 0.4), 0.5 + min(0.9, 0.7), 0.5 + min(0.2, 0.1)]
        # = [0.5 + 0.3, 0.5 + 0.4, 0.5 + 0.7, 0.5 + 0.1]
        expected = torch.tensor([0.8, 0.9, 1.2, 0.6], device=device)
        assert torch.allclose(extrinsic, expected)

    def test_vfs_variable_strategy(self, bar_index_map_dual):
        """VFS variable: reward = vfs[variable] * weight (escape hatch)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                ),
                VariableDef(
                    id="custom_reward",
                    scope="agent",
                    type="scalar",
                    default=0.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        # Set custom reward values in VFS
        vfs_registry.set("custom_reward", torch.tensor([0.5, 1.0, 1.5, 2.0], device=device), writer="engine")

        # Use variable_bonuses for weight and variable
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="vfs_variable",
                base=0.0,
                variable_bonuses=[
                    VariableBonusConfig(variable="custom_reward", weight=2.0),
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Meters not used for vfs_variable strategy
        meters = torch.tensor([[1.0], [1.0], [1.0], [1.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: weight * custom_reward = 2.0 * [0.5, 1.0, 1.5, 2.0]
        expected = torch.tensor([1.0, 2.0, 3.0, 4.0], device=device)
        assert torch.allclose(extrinsic, expected)

    def test_hybrid_strategy(self, bar_index_map_dual):
        """Hybrid: combine multiple approaches (simplified as weighted bars)"""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Simplified hybrid: combines multiple weighted bars
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="hybrid",
                base=1.0,
                bar_bonuses=[
                    BarBonusConfig(bar="energy", center=0.0, scale=1.5),  # Linear term
                    BarBonusConfig(bar="health", center=0.5, scale=0.5),  # Shaped term
                ],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # meters: [energy, health]
        meters = torch.tensor([[0.5, 0.5], [0.8, 0.6], [0.2, 0.4], [1.0, 1.0]], device=device)
        dones = torch.tensor([False, False, False, False], device=device)

        extrinsic = engine.extrinsic_fn(meters, dones)

        # Expected: base + 1.5*energy + 0.5*(health-0.5)
        # [1.0 + 1.5*0.5 + 0.5*(0.5-0.5), 1.0 + 1.5*0.8 + 0.5*(0.6-0.5), ...]
        expected = torch.tensor([1.75, 2.25, 1.25, 2.75], device=device)
        assert torch.allclose(extrinsic, expected, atol=1e-5)


class TestShapingBonuses:
    """Test shaping bonus compilation and evaluation."""

    def test_approach_reward_bonus(self, bar_index_map_single):
        """approach_reward bonus rewards moving toward target affordance."""
        from townlet.config.drive_as_code import ApproachRewardConfig

        device = torch.device("cpu")
        num_agents = 3

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                ApproachRewardConfig(
                    type="approach_reward",
                    weight=0.5,
                    target_affordance="Bed",
                    max_distance=10.0,
                )
            ],
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent 0: distance=2, Agent 1: distance=5, Agent 2: distance≈19 (far/clamped)
        agent_positions = torch.tensor([[1.0, 1.0], [8.0, 1.0], [20.0, 20.0]], device=device)
        affordance_positions = {"Bed": torch.tensor([3.0, 1.0], device=device)}

        # Calculate shaping bonuses
        bonuses = torch.zeros(num_agents, device=device)
        for shaping_fn in engine.shaping_fns:
            bonuses += shaping_fn(agent_positions=agent_positions, affordance_positions=affordance_positions)

        # Agent 0: distance=2 → bonus = 0.5 * (1 - 2/10) = 0.4
        # Agent 1: distance=5 → bonus = 0.5 * (1 - 5/10) = 0.25
        # Agent 2: distance≈24 → bonus = 0.0 (clamped)
        assert torch.isclose(bonuses[0], torch.tensor(0.4, device=device), atol=1e-5)
        assert torch.isclose(bonuses[1], torch.tensor(0.25, device=device), atol=1e-5)
        assert bonuses[2] == 0.0

    def test_completion_bonus(self, bar_index_map_single):
        """completion_bonus gives fixed bonus when agent completes interaction."""
        from townlet.config.drive_as_code import CompletionBonusConfig

        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                CompletionBonusConfig(
                    type="completion_bonus",
                    weight=1.0,
                    affordance="Bed",
                )
            ],
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent 0: completed Bed, Agent 1: completed Fridge, Agent 2: no completion, Agent 3: completed Bed
        last_action_affordance = ["Bed", "Fridge", None, "Bed"]

        # Calculate shaping bonuses
        bonuses = torch.zeros(num_agents, device=device)
        for shaping_fn in engine.shaping_fns:
            bonuses += shaping_fn(last_action_affordance=last_action_affordance)

        # Agent 0: completed Bed → bonus = 1.0
        # Agent 1: completed Fridge (not target) → bonus = 0.0
        # Agent 2: no completion → bonus = 0.0
        # Agent 3: completed Bed → bonus = 1.0
        assert bonuses[0] == 1.0
        assert bonuses[1] == 0.0
        assert bonuses[2] == 0.0
        assert bonuses[3] == 1.0

    def test_efficiency_bonus(self, bar_index_map_single):
        """efficiency_bonus rewards maintaining bar above threshold."""
        from townlet.config.drive_as_code import EfficiencyBonusConfig

        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                EfficiencyBonusConfig(
                    type="efficiency_bonus",
                    weight=0.5,
                    bar="energy",
                    threshold=0.7,
                )
            ],
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent 0: energy=0.9 (above), Agent 1: energy=0.7 (at threshold), Agent 2: energy=0.5 (below), Agent 3: energy=0.0 (below)
        meters = torch.tensor([[0.9], [0.7], [0.5], [0.0]], device=device)

        # Calculate shaping bonuses
        bonuses = torch.zeros(num_agents, device=device)
        for shaping_fn in engine.shaping_fns:
            bonuses += shaping_fn(meters=meters)

        # Agent 0: energy >= 0.7 → bonus = 0.5
        # Agent 1: energy >= 0.7 → bonus = 0.5
        # Agent 2: energy < 0.7 → bonus = 0.0
        # Agent 3: energy < 0.7 → bonus = 0.0
        assert bonuses[0] == 0.5
        assert bonuses[1] == 0.5
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_state_achievement_bonus(self, bar_index_map_dual):
        """state_achievement rewards when ALL conditions are met."""
        from townlet.config.drive_as_code import BarCondition, StateAchievementConfig

        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy", "health"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                StateAchievementConfig(
                    type="state_achievement",
                    weight=2.0,
                    conditions=[
                        BarCondition(bar="energy", min_value=0.8),
                        BarCondition(bar="health", min_value=0.7),
                    ],
                )
            ],
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Agent 0: both above thresholds, Agent 1: energy low, Agent 2: health low, Agent 3: both low
        meters = torch.tensor(
            [
                [0.9, 0.8],  # Agent 0: energy=0.9, health=0.8
                [0.5, 0.9],  # Agent 1: energy=0.5, health=0.9
                [0.9, 0.5],  # Agent 2: energy=0.9, health=0.5
                [0.5, 0.5],  # Agent 3: energy=0.5, health=0.5
            ],
            device=device,
        )

        # Calculate shaping bonuses
        bonuses = torch.zeros(num_agents, device=device)
        for shaping_fn in engine.shaping_fns:
            bonuses += shaping_fn(meters=meters)

        # Agent 0: both conditions met → bonus = 2.0
        # Agent 1: energy < 0.8 → bonus = 0.0
        # Agent 2: health < 0.7 → bonus = 0.0
        # Agent 3: both below → bonus = 0.0
        assert bonuses[0] == 2.0
        assert bonuses[1] == 0.0
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_streak_bonus(self, bar_index_map_dual):
        """streak_bonus rewards consecutive uses of affordance."""
        from townlet.config.drive_as_code import StreakBonusConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                StreakBonusConfig(
                    type="streak_bonus",
                    weight=3.0,
                    affordance="Bed",
                    min_streak=3,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Agent 0: streak=5 (exceeds min), Agent 1: streak=3 (meets min),
        # Agent 2: streak=2 (below min), Agent 3: streak=0 (no streak)
        affordance_streak = {
            "Bed": torch.tensor([5, 3, 2, 0], device=device),
            "Fridge": torch.tensor([1, 1, 1, 1], device=device),
        }

        bonuses = engine.shaping_fns[0](affordance_streak=affordance_streak)

        # Agent 0,1: streak >= 3 → bonus = 3.0
        # Agent 2,3: streak < 3 → bonus = 0.0
        assert bonuses[0] == 3.0
        assert bonuses[1] == 3.0
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_diversity_bonus(self, bar_index_map_single):
        """diversity_bonus rewards using many different affordances."""
        from townlet.config.drive_as_code import DiversityBonusConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                DiversityBonusConfig(
                    type="diversity_bonus",
                    weight=2.5,
                    min_unique_affordances=3,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent 0: 5 unique (exceeds), Agent 1: 3 unique (meets),
        # Agent 2: 2 unique (below), Agent 3: 0 unique (none)
        unique_affordances_used = torch.tensor([5, 3, 2, 0], device=device)

        bonuses = engine.shaping_fns[0](unique_affordances_used=unique_affordances_used)

        # Agent 0,1: unique >= 3 → bonus = 2.5
        # Agent 2,3: unique < 3 → bonus = 0.0
        assert bonuses[0] == 2.5
        assert bonuses[1] == 2.5
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_timing_bonus(self, bar_index_map_single):
        """timing_bonus rewards using affordance during specific time windows."""
        from townlet.config.drive_as_code import TimeRange, TimingBonusConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                TimingBonusConfig(
                    type="timing_bonus",
                    weight=1.0,
                    time_ranges=[
                        TimeRange(start_hour=22, end_hour=6, affordance="Bed", multiplier=2.0),
                        TimeRange(start_hour=12, end_hour=13, affordance="Fridge", multiplier=1.5),
                    ],
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent 0: hour=23, last_action=Bed (in range 22-6, matches) → bonus = 1.0 * 2.0
        # Agent 1: hour=12, last_action=Fridge (in range 12-13, matches) → bonus = 1.0 * 1.5
        # Agent 2: hour=10, last_action=Bed (not in range 22-6) → bonus = 0.0
        # Agent 3: hour=12, last_action=Bed (in range 12-13, wrong affordance) → bonus = 0.0
        current_hour = torch.tensor([23, 12, 10, 12], device=device)
        last_action_affordance = ["Bed", "Fridge", "Bed", "Bed"]

        bonuses = engine.shaping_fns[0](current_hour=current_hour, last_action_affordance=last_action_affordance)

        # Agent 0: timing match → 1.0 * 2.0 = 2.0
        # Agent 1: timing match → 1.0 * 1.5 = 1.5
        # Agent 2: no match → 0.0
        # Agent 3: no match → 0.0
        assert bonuses[0] == 2.0
        assert bonuses[1] == 1.5
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_economic_efficiency(self):
        """economic_efficiency rewards maintaining money above threshold."""
        from townlet.config.drive_as_code import EconomicEfficiencyConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy", "money"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                EconomicEfficiencyConfig(
                    type="economic_efficiency",
                    weight=3.0,
                    money_bar="money",
                    min_balance=0.5,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        # This test uses energy and money bars
        bar_index_map = {"energy": 0, "money": 1}
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map)

        # Agent 0: money=0.8 (above), Agent 1: money=0.5 (at threshold),
        # Agent 2: money=0.3 (below), Agent 3: money=0.0 (below)
        meters = torch.tensor(
            [
                [1.0, 0.8],  # [energy, money]
                [1.0, 0.5],
                [1.0, 0.3],
                [1.0, 0.0],
            ],
            device=device,
        )

        bonuses = engine.shaping_fns[0](meters=meters)

        # Agent 0,1: money >= 0.5 → bonus = 3.0
        # Agent 2,3: money < 0.5 → bonus = 0.0
        assert bonuses[0] == 3.0
        assert bonuses[1] == 3.0
        assert bonuses[2] == 0.0
        assert bonuses[3] == 0.0

    def test_balance_bonus(self, bar_index_map_dual):
        """balance_bonus rewards keeping multiple bars balanced."""
        from townlet.config.drive_as_code import BalanceBonusConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy", "health"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                BalanceBonusConfig(
                    type="balance_bonus",
                    weight=5.0,
                    bars=["energy", "health"],
                    max_imbalance=0.2,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Agent 0: perfect balance (0.5, 0.5) → imbalance=0.0
        # Agent 1: slight imbalance (0.6, 0.5) → imbalance=0.1 (within threshold)
        # Agent 2: at threshold (0.8, 0.6) → imbalance=0.2 (at threshold, gets bonus)
        # Agent 3: too much imbalance (1.0, 0.5) → imbalance=0.5 (exceeds threshold)
        meters = torch.tensor(
            [
                [0.5, 0.5],  # Agent 0
                [0.6, 0.5],  # Agent 1
                [0.8, 0.6],  # Agent 2
                [1.0, 0.5],  # Agent 3
            ],
            device=device,
        )

        bonuses = engine.shaping_fns[0](meters=meters)

        # Agents 0,1,2: imbalance <= 0.2 → bonus = 5.0
        # Agent 3: imbalance > 0.2 → bonus = 0.0
        assert bonuses[0] == 5.0
        assert bonuses[1] == 5.0
        assert bonuses[2] == 5.0
        assert bonuses[3] == 0.0

    def test_crisis_avoidance(self, bar_index_map_dual):
        """crisis_avoidance rewards staying above crisis threshold."""
        from townlet.config.drive_as_code import CrisisAvoidanceConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                CrisisAvoidanceConfig(
                    type="crisis_avoidance",
                    weight=3.0,
                    bar="energy",
                    crisis_threshold=0.3,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 5
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Agent 0: energy=0.8 (well above crisis) → bonus
        # Agent 1: energy=0.4 (above crisis) → bonus
        # Agent 2: energy=0.31 (just above crisis) → bonus
        # Agent 3: energy=0.3 (at crisis, NOT above) → no bonus
        # Agent 4: energy=0.1 (in crisis) → no bonus
        meters = torch.tensor([[0.8], [0.4], [0.31], [0.3], [0.1]], device=device)

        bonuses = engine.shaping_fns[0](meters=meters)

        # Agents 0,1,2: energy > 0.3 → bonus = 3.0
        # Agents 3,4: energy <= 0.3 → bonus = 0.0
        assert bonuses[0] == 3.0
        assert bonuses[1] == 3.0
        assert bonuses[2] == 3.0
        assert bonuses[3] == 0.0
        assert bonuses[4] == 0.0

    def test_vfs_variable_bonus(self, bar_index_map_single):
        """vfs_variable bonus uses VFS variable value as bonus."""
        from townlet.config.drive_as_code import VfsVariableConfig

        dac_config = DriveAsCodeConfig(
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=[]),
            shaping=[
                VfsVariableConfig(
                    type="vfs_variable",
                    weight=2.0,
                    variable="custom_bonus",
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="custom_bonus",
                    scope="agent",
                    type="scalar",
                    default=0.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        # Register VFS variable with different values per agent
        vfs_registry.set("custom_bonus", torch.tensor([1.0, 0.5, 0.0, -0.5], device=device), writer="engine")

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Call bonus (no kwargs needed - reads from VFS)
        bonuses = engine.shaping_fns[0]()

        # Bonus: weight * variable_value
        # Agent 0: 2.0 * 1.0 = 2.0
        # Agent 1: 2.0 * 0.5 = 1.0
        # Agent 2: 2.0 * 0.0 = 0.0
        # Agent 3: 2.0 * -0.5 = -1.0 (negative bonus!)
        assert bonuses[0] == 2.0
        assert bonuses[1] == 1.0
        assert bonuses[2] == 0.0
        assert bonuses[3] == -1.0


class TestShapingBonusEdgeCases:
    """Test edge cases for shaping bonuses (missing kwargs, invalid data)."""

    def test_approach_reward_missing_affordance(self, bar_index_map_single):
        """approach_reward returns zeros when target affordance not in positions."""
        from townlet.config.drive_as_code import ApproachRewardConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                ApproachRewardConfig(
                    type="approach_reward",
                    weight=0.5,
                    target_affordance="Bed",
                    max_distance=10.0,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Agent positions provided, but affordance_positions does NOT include "Bed"
        agent_positions = torch.tensor([[1.0, 1.0], [3.0, 3.0], [5.0, 5.0]], device=device)
        affordance_positions = {"Fridge": torch.tensor([10.0, 10.0], device=device)}  # No "Bed"

        # Call the compiled shaping function directly
        bonuses = engine.shaping_fns[0](
            agent_positions=agent_positions,
            affordance_positions=affordance_positions,
        )

        # Should return zeros for all agents (affordance not found)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_completion_bonus_missing_kwarg(self, bar_index_map_single):
        """completion_bonus returns zeros when last_action_affordance missing."""
        from townlet.config.drive_as_code import CompletionBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                CompletionBonusConfig(
                    type="completion_bonus",
                    weight=5.0,
                    affordance="Bed",
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Call without providing last_action_affordance kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_efficiency_bonus_missing_kwarg(self, bar_index_map_single):
        """efficiency_bonus returns zeros when meters missing."""
        from townlet.config.drive_as_code import EfficiencyBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                EfficiencyBonusConfig(
                    type="efficiency_bonus",
                    weight=2.0,
                    bar="energy",
                    threshold=0.7,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Call without providing meters kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_state_achievement_missing_kwarg(self, bar_index_map_single):
        """state_achievement returns zeros when meters missing."""
        from townlet.config.drive_as_code import BarCondition, StateAchievementConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                StateAchievementConfig(
                    type="state_achievement",
                    weight=10.0,
                    conditions=[
                        BarCondition(bar="energy", min_value=0.8),
                    ],
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Call without providing meters kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_streak_bonus_missing_kwarg(self, bar_index_map_dual):
        """streak_bonus returns zeros when affordance_streak missing."""
        from townlet.config.drive_as_code import StreakBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                StreakBonusConfig(
                    type="streak_bonus",
                    weight=5.0,
                    affordance="Bed",
                    min_streak=2,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing affordance_streak kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_streak_bonus_affordance_not_found(self, bar_index_map_single):
        """streak_bonus returns zeros when target affordance not in streak dict."""
        from townlet.config.drive_as_code import StreakBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                StreakBonusConfig(
                    type="streak_bonus",
                    weight=5.0,
                    affordance="Bed",
                    min_streak=2,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Provide affordance_streak dict but without "Bed"
        affordance_streak = {"Fridge": torch.tensor([5, 5, 5], device=device)}

        bonuses = engine.shaping_fns[0](affordance_streak=affordance_streak)

        # Should return zeros (affordance not in dict)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_diversity_bonus_missing_kwarg(self, bar_index_map_dual):
        """diversity_bonus returns zeros when unique_affordances_used missing."""
        from townlet.config.drive_as_code import DiversityBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                DiversityBonusConfig(
                    type="diversity_bonus",
                    weight=5.0,
                    min_unique_affordances=2,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing unique_affordances_used kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_timing_bonus_missing_kwargs(self, bar_index_map_dual):
        """timing_bonus returns zeros when current_hour or last_action_affordance missing."""
        from townlet.config.drive_as_code import TimeRange, TimingBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                TimingBonusConfig(
                    type="timing_bonus",
                    weight=5.0,
                    time_ranges=[
                        TimeRange(start_hour=22, end_hour=6, affordance="Bed", multiplier=2.0),
                    ],
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing any kwargs
        bonuses = engine.shaping_fns[0]()
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

        # Call with only current_hour (missing last_action_affordance)
        current_hour = torch.tensor([23, 12, 10], device=device)
        bonuses = engine.shaping_fns[0](current_hour=current_hour)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

        # Call with only last_action_affordance (missing current_hour)
        last_action_affordance = ["Bed", "Bed", "Bed"]
        bonuses = engine.shaping_fns[0](last_action_affordance=last_action_affordance)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_economic_efficiency_missing_kwarg(self, bar_index_map_dual):
        """economic_efficiency returns zeros when meters missing."""
        from townlet.config.drive_as_code import EconomicEfficiencyConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy", "money"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                EconomicEfficiencyConfig(
                    type="economic_efficiency",
                    weight=5.0,
                    money_bar="money",
                    min_balance=0.7,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing meters kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_balance_bonus_missing_kwarg(self, bar_index_map_dual):
        """balance_bonus returns zeros when meters missing."""
        from townlet.config.drive_as_code import BalanceBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy", "health"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                BalanceBonusConfig(
                    type="balance_bonus",
                    weight=5.0,
                    bars=["energy", "health"],
                    max_imbalance=0.2,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing meters kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_crisis_avoidance_missing_kwarg(self, bar_index_map_dual):
        """crisis_avoidance returns zeros when meters missing."""
        from townlet.config.drive_as_code import CrisisAvoidanceConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                CrisisAvoidanceConfig(
                    type="crisis_avoidance",
                    weight=3.0,
                    bar="energy",
                    crisis_threshold=0.3,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Call without providing meters kwarg
        bonuses = engine.shaping_fns[0]()

        # Should return zeros (kwarg missing)
        assert torch.allclose(bonuses, torch.zeros(num_agents, device=device))

    def test_vfs_variable_missing_variable(self, bar_index_map_single):
        """vfs_variable raises error when variable not in registry."""
        import pytest

        from townlet.config.drive_as_code import VfsVariableConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(type="multiplicative", bars=["energy"]),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                VfsVariableConfig(
                    type="vfs_variable",
                    weight=2.0,
                    variable="nonexistent_var",
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )
        # Don't register the variable

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Should raise KeyError when trying to read missing variable
        with pytest.raises(KeyError, match="nonexistent_var"):
            engine.shaping_fns[0]()


class TestCalculateRewards:
    """Test full calculate_rewards() composition logic."""

    def test_calculate_rewards_composition(self, bar_index_map_single):
        """calculate_rewards composes extrinsic + intrinsic + shaping."""
        from townlet.config.drive_as_code import EfficiencyBonusConfig

        # Setup DAC with:
        # - Extrinsic: multiplicative (energy only) → base=1.0 * energy
        # - Intrinsic: provided externally
        # - Modifier: "low_energy" suppresses intrinsic when energy < 0.5
        # - Shaping: efficiency_bonus (energy >= 0.7 → +2.0)

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "low_energy": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="low", min=0.0, max=0.5, multiplier=0.5),
                        RangeConfig(name="normal", min=0.5, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=["low_energy"]),
            shaping=[
                EfficiencyBonusConfig(
                    type="efficiency_bonus",
                    weight=2.0,
                    bar="energy",
                    threshold=0.7,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 4
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Test scenarios (after bug fixes):
        # Agent 0: energy=0.8 → extrinsic=0.8, intrinsic=(1.0*0.1)×1.0=0.1, shaping=2.0 → total=2.9
        # Agent 1: energy=0.6 → extrinsic=0.6, intrinsic=(1.0*0.1)×1.0=0.1, shaping=0.0 → total=0.7
        # Agent 2: energy=0.3 → extrinsic=0.3, intrinsic=(1.0*0.1)×0.5=0.05, shaping=0.0 → total=0.35
        # Agent 3: DEAD (energy=0.0) → extrinsic=0.0, intrinsic=0.0 (masked), shaping=0.0 (masked) → total=0.0
        # Note: After bug fixes, dead agents now correctly receive 0.0 for intrinsic and shaping

        meters = torch.tensor([[0.8], [0.6], [0.3], [0.0]], device=device)
        dones = torch.tensor([False, False, False, True], device=device)
        intrinsic_raw = torch.tensor([1.0, 1.0, 1.0, 1.0], device=device)
        step_counts = torch.tensor([10, 10, 10, 10], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Verify extrinsic (dead agents get 0.0)
        assert torch.allclose(components["extrinsic"], torch.tensor([0.8, 0.6, 0.3, 0.0], device=device))

        # Verify intrinsic (base_weight applied, modifiers applied, dead agents get 0.0)
        # intrinsic = intrinsic_raw * base_weight * modifier_weight
        # Agent 0: 1.0 * 0.1 * 1.0 = 0.1
        # Agent 1: 1.0 * 0.1 * 1.0 = 0.1
        # Agent 2: 1.0 * 0.1 * 0.5 = 0.05
        # Agent 3: masked to 0.0 (dead)
        assert torch.allclose(components["intrinsic"], torch.tensor([0.1, 0.1, 0.05, 0.0], device=device))

        # Verify shaping (dead agents get 0.0)
        assert torch.allclose(components["shaping"], torch.tensor([2.0, 0.0, 0.0, 0.0], device=device))

        # Verify total
        expected_total = torch.tensor([2.9, 0.7, 0.35, 0.0], device=device)
        assert torch.allclose(total_rewards, expected_total)

        # Verify intrinsic weights
        expected_weights = torch.tensor([1.0, 1.0, 0.5, 0.5], device=device)
        assert torch.allclose(intrinsic_weights, expected_weights)

    def test_calculate_rewards_all_components(self, bar_index_map_dual):
        """calculate_rewards integrates all DAC components."""
        from townlet.config.drive_as_code import CompletionBonusConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "health_crisis": ModifierConfig(
                    bar="health",
                    ranges=[
                        RangeConfig(name="crisis", min=0.0, max=0.3, multiplier=0.0),
                        RangeConfig(name="normal", min=0.3, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.1, apply_modifiers=["health_crisis"]),
            shaping=[
                CompletionBonusConfig(
                    type="completion_bonus",
                    weight=5.0,
                    affordance="Bed",
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="health",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        meters = torch.tensor([[1.0, 1.0], [0.5, 0.5], [0.8, 0.2]], device=device)
        dones = torch.tensor([False, False, False], device=device)
        intrinsic_raw = torch.tensor([2.0, 2.0, 2.0], device=device)
        step_counts = torch.tensor([5, 5, 5], device=device)

        # Agent 0 just used Bed, agent 1 just used Fridge, agent 2 did nothing
        last_action_affordance = ["Bed", "Fridge", None]

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
            last_action_affordance=last_action_affordance,
        )

        # After bug fixes (base_weight now applied):
        # Agent 0: extrinsic=1.0*1.0=1.0, intrinsic=(2.0*0.1)*1.0=0.2, shaping=5.0 → total=6.2
        # Agent 1: extrinsic=0.5*0.5=0.25, intrinsic=(2.0*0.1)*1.0=0.2, shaping=0.0 → total=0.45
        # Agent 2: extrinsic=0.8*0.2=0.16, intrinsic=(2.0*0.1)*0.0=0.0 (health crisis), shaping=0.0 → total=0.16

        assert torch.allclose(total_rewards[0], torch.tensor(6.2, device=device))
        assert torch.allclose(total_rewards[1], torch.tensor(0.45, device=device))
        assert torch.allclose(total_rewards[2], torch.tensor(0.16, device=device))

    def test_components_includes_intrinsic_raw(self, bar_index_map_dual):
        """Components dict includes intrinsic_raw (before modifiers, after base_weight)."""
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "energy_crisis": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="crisis", min=0.0, max=0.2, multiplier=0.0),
                        RangeConfig(name="normal", min=0.2, max=1.0, multiplier=1.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="rnd", base_weight=0.5, apply_modifiers=["energy_crisis"]),
        )

        device = torch.device("cpu")
        num_agents = 3
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="health",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Test scenarios:
        # Agent 0: energy=1.0 (normal), health=1.0 → modifier=1.0
        # Agent 1: energy=0.5 (normal), health=0.8 → modifier=1.0
        # Agent 2: energy=0.1 (crisis), health=0.5 → modifier=0.0
        meters = torch.tensor([[1.0, 1.0], [0.5, 0.8], [0.1, 0.5]], device=device)
        dones = torch.tensor([False, False, False], device=device)
        intrinsic_raw = torch.tensor([2.0, 3.0, 4.0], device=device)
        step_counts = torch.tensor([5, 5, 5], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Verify components dict contains intrinsic_raw
        assert "intrinsic_raw" in components, "Components dict must include intrinsic_raw"

        # Verify intrinsic_raw = intrinsic_raw_input * base_weight (before modifiers)
        # Agent 0: 2.0 * 0.5 = 1.0
        # Agent 1: 3.0 * 0.5 = 1.5
        # Agent 2: 4.0 * 0.5 = 2.0
        expected_intrinsic_raw = torch.tensor([1.0, 1.5, 2.0], device=device)
        assert torch.allclose(
            components["intrinsic_raw"], expected_intrinsic_raw
        ), "intrinsic_raw should be intrinsic_raw_input * base_weight (before modifiers)"

        # Verify intrinsic = intrinsic_raw * modifier (after modifiers)
        # Agent 0: 1.0 * 1.0 = 1.0
        # Agent 1: 1.5 * 1.0 = 1.5
        # Agent 2: 2.0 * 0.0 = 0.0 (crisis suppression)
        expected_intrinsic = torch.tensor([1.0, 1.5, 0.0], device=device)
        assert torch.allclose(components["intrinsic"], expected_intrinsic), "intrinsic should be intrinsic_raw * modifier"

        # Verify intrinsic_weights (modifier values)
        expected_weights = torch.tensor([1.0, 1.0, 0.0], device=device)
        assert torch.allclose(intrinsic_weights, expected_weights), "intrinsic_weights should reflect modifier application"

    def test_calculate_rewards_no_intrinsic(self, bar_index_map_single):
        """calculate_rewards works when intrinsic_raw is zeros."""
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=2.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        device = torch.device("cpu")
        num_agents = 2
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        meters = torch.tensor([[1.0], [0.5]], device=device)
        dones = torch.tensor([False, False], device=device)
        intrinsic_raw = torch.tensor([0.0, 0.0], device=device)
        step_counts = torch.tensor([1, 1], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Should have only extrinsic rewards
        assert torch.allclose(total_rewards, torch.tensor([2.0, 1.0], device=device))
        assert torch.allclose(components["intrinsic"], torch.tensor([0.0, 0.0], device=device))

    def test_calculate_rewards_kwargs_propagation(self, bar_index_map_dual):
        """calculate_rewards passes kwargs to shaping bonuses."""
        from townlet.config.drive_as_code import ApproachRewardConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            shaping=[
                ApproachRewardConfig(
                    type="approach_reward",
                    weight=1.0,
                    target_affordance="Bed",
                    max_distance=5.0,
                )
            ],
        )

        device = torch.device("cpu")
        num_agents = 2
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="health",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        meters = torch.tensor([[1.0, 1.0], [1.0, 1.0]], device=device)
        dones = torch.tensor([False, False], device=device)
        intrinsic_raw = torch.tensor([0.0, 0.0], device=device)
        step_counts = torch.tensor([1, 1], device=device)

        # Agent 0 at distance 2.0 from Bed, Agent 1 at distance 4.0
        agent_positions = torch.tensor([[0.0, 0.0], [3.0, 0.0]], device=device)
        affordance_positions = {"Bed": torch.tensor([0.0, 2.0], device=device)}

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
            agent_positions=agent_positions,
            affordance_positions=affordance_positions,
        )

        # Shaping bonus should be computed based on Euclidean distance
        # Agent 0: distance=sqrt((0-0)^2 + (0-2)^2) = 2.0, bonus = 1.0 * (1 - 2.0/5.0) = 0.6
        # Agent 1: distance=sqrt((3-0)^2 + (0-2)^2) = sqrt(13) ≈ 3.606, bonus = 1.0 * (1 - 3.606/5.0) ≈ 0.2789
        assert torch.allclose(components["shaping"][0], torch.tensor(0.6, device=device))
        assert torch.allclose(components["shaping"][1], torch.tensor(1.0 * (1.0 - 3.606 / 5.0), device=device), atol=1e-3)


class TestDACEngineBugFixes:
    """Tests for critical bug fixes in DAC Engine reward calculation."""

    def test_dead_agents_receive_zero_rewards(self, bar_index_map_dual):
        """BUG 1: Dead agents must receive 0.0 for intrinsic and shaping rewards."""
        device = torch.device("cpu")
        num_agents = 4

        # Create VFS registry
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="health",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        # Create DAC config with intrinsic and shaping
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="rnd",
                base_weight=0.5,
                apply_modifiers=[],
            ),
            shaping=[
                {
                    "type": "efficiency_bonus",
                    "weight": 0.2,
                    "bar": "energy",
                    "threshold": 0.5,
                }
            ],
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        # Test scenario: 2 alive agents, 2 dead agents
        meters = torch.tensor(
            [
                [0.8, 0.9],
                [0.0, 0.5],
                [0.7, 0.8],
                [0.6, 0.0],
            ],  # Agent 0: alive  # Agent 1: dead (energy=0)  # Agent 2: alive  # Agent 3: dead (health=0)
            device=device,
        )
        dones = torch.tensor([False, True, False, True], device=device)
        intrinsic_raw = torch.tensor([0.1, 0.2, 0.15, 0.25], device=device)
        step_counts = torch.tensor([10, 10, 10, 10], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Dead agents (indices 1, 3) must have 0.0 for intrinsic rewards
        assert components["intrinsic"][1] == 0.0, f"Dead agent 1 intrinsic: {components['intrinsic'][1]}"
        assert components["intrinsic"][3] == 0.0, f"Dead agent 3 intrinsic: {components['intrinsic'][3]}"

        # Alive agents (indices 0, 2) should have non-zero intrinsic
        assert components["intrinsic"][0] > 0.0, "Alive agent 0 should have intrinsic reward"
        assert components["intrinsic"][2] > 0.0, "Alive agent 2 should have intrinsic reward"

        # Dead agents (indices 1, 3) must have 0.0 for shaping rewards
        assert components["shaping"][1] == 0.0, f"Dead agent 1 shaping: {components['shaping'][1]}"
        assert components["shaping"][3] == 0.0, f"Dead agent 3 shaping: {components['shaping'][3]}"

        # Alive agents (indices 0, 2) should have non-zero shaping (both energy > 0.5)
        assert components["shaping"][0] > 0.0, "Alive agent 0 should have shaping reward"
        assert components["shaping"][2] > 0.0, "Alive agent 2 should have shaping reward"

        # Extrinsic already correctly masks dead agents (existing behavior)
        assert components["extrinsic"][1] == 0.0, "Dead agent 1 extrinsic should be 0"
        assert components["extrinsic"][3] == 0.0, "Dead agent 3 extrinsic should be 0"

    def test_intrinsic_base_weight_applied(self, bar_index_map_single):
        """BUG 2: intrinsic.base_weight must be applied to intrinsic rewards."""
        device = torch.device("cpu")
        num_agents = 2

        # Create VFS registry
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Test with base_weight=0.3 and NO modifiers
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="rnd",
                base_weight=0.3,  # This should multiply intrinsic_raw
                apply_modifiers=[],
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        meters = torch.tensor([[1.0], [1.0]], device=device)
        dones = torch.tensor([False, False], device=device)
        intrinsic_raw = torch.tensor([1.0, 2.0], device=device)
        step_counts = torch.tensor([1, 1], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Expected: intrinsic = intrinsic_raw * base_weight
        # Agent 0: 1.0 * 0.3 = 0.3
        # Agent 1: 2.0 * 0.3 = 0.6
        assert torch.allclose(
            components["intrinsic"][0], torch.tensor(0.3, device=device)
        ), f"Agent 0: expected 0.3, got {components['intrinsic'][0]}"
        assert torch.allclose(
            components["intrinsic"][1], torch.tensor(0.6, device=device)
        ), f"Agent 1: expected 0.6, got {components['intrinsic'][1]}"

    def test_intrinsic_apply_modifiers_honored(self, bar_index_map_single):
        """BUG 3: intrinsic.apply_modifiers list must be honored (not apply all modifiers)."""
        device = torch.device("cpu")
        num_agents = 2

        # Create VFS registry
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Create two modifiers: modifier_a (2x) and modifier_b (3x)
        # But only apply modifier_a to intrinsic
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "modifier_a": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="all", min=0.0, max=1.0, multiplier=2.0),
                    ],
                ),
                "modifier_b": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="all", min=0.0, max=1.0, multiplier=3.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="rnd",
                base_weight=1.0,
                apply_modifiers=["modifier_a"],  # Only apply modifier_a (NOT modifier_b)
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        meters = torch.tensor([[0.5], [0.5]], device=device)
        dones = torch.tensor([False, False], device=device)
        intrinsic_raw = torch.tensor([1.0, 1.0], device=device)
        step_counts = torch.tensor([1, 1], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Expected: intrinsic = intrinsic_raw * base_weight * modifier_a
        # Should be: 1.0 * 1.0 * 2.0 = 2.0
        # Should NOT be: 1.0 * 1.0 * 2.0 * 3.0 = 6.0 (if all modifiers applied)
        assert torch.allclose(
            components["intrinsic"][0], torch.tensor(2.0, device=device)
        ), f"Agent 0: expected 2.0, got {components['intrinsic'][0]} (if 6.0, all modifiers applied incorrectly)"
        assert torch.allclose(
            components["intrinsic"][1], torch.tensor(2.0, device=device)
        ), f"Agent 1: expected 2.0, got {components['intrinsic'][1]}"

    def test_extrinsic_apply_modifiers_honored(self, bar_index_map_dual):
        """BUG 4: extrinsic.apply_modifiers list must be honored for all 9 strategies."""
        device = torch.device("cpu")
        num_agents = 2

        # Create VFS registry
        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
                VariableDef(
                    id="health",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    lifetime="episode",
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                ),
            ],
            num_agents=num_agents,
            device=device,
        )

        # Create a modifier that applies 2x multiplier
        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "double_modifier": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="all", min=0.0, max=1.0, multiplier=2.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy", "health"],
                apply_modifiers=["double_modifier"],  # Apply modifier to extrinsic
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="none",
                base_weight=0.0,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_dual)

        meters = torch.tensor([[0.5, 0.4], [0.6, 0.3]], device=device)
        dones = torch.tensor([False, False], device=device)
        intrinsic_raw = torch.tensor([0.0, 0.0], device=device)
        step_counts = torch.tensor([1, 1], device=device)

        total_rewards, intrinsic_weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Expected: extrinsic = (base * energy * health) * modifier
        # Agent 0: (1.0 * 0.5 * 0.4) * 2.0 = 0.2 * 2.0 = 0.4
        # Agent 1: (1.0 * 0.6 * 0.3) * 2.0 = 0.18 * 2.0 = 0.36
        # Without modifier bug fix, would be: 0.2 and 0.18
        assert torch.allclose(
            components["extrinsic"][0], torch.tensor(0.4, device=device)
        ), f"Agent 0: expected 0.4, got {components['extrinsic'][0]} (if 0.2, modifier not applied)"
        assert torch.allclose(
            components["extrinsic"][1], torch.tensor(0.36, device=device)
        ), f"Agent 1: expected 0.36, got {components['extrinsic'][1]}"

        # Test another strategy: additive_unweighted
        dac_config_additive = DriveAsCodeConfig(
            version="1.0",
            modifiers={
                "double_modifier": ModifierConfig(
                    bar="energy",
                    ranges=[
                        RangeConfig(name="all", min=0.0, max=1.0, multiplier=2.0),
                    ],
                ),
            },
            extrinsic=ExtrinsicStrategyConfig(
                type="additive_unweighted",
                base=0.0,
                bars=["energy", "health"],
                apply_modifiers=["double_modifier"],
            ),
            intrinsic=IntrinsicStrategyConfig(
                strategy="none",
                base_weight=0.0,
            ),
        )

        engine_additive = DACEngine(dac_config_additive, vfs_registry, device, num_agents, bar_index_map_dual)

        total_rewards_add, _, components_add = engine_additive.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Expected: extrinsic = (base + energy + health) * modifier
        # Agent 0: (0.0 + 0.5 + 0.4) * 2.0 = 0.9 * 2.0 = 1.8
        # Agent 1: (0.0 + 0.6 + 0.3) * 2.0 = 0.9 * 2.0 = 1.8
        assert torch.allclose(
            components_add["extrinsic"][0], torch.tensor(1.8, device=device)
        ), f"Additive Agent 0: expected 1.8, got {components_add['extrinsic'][0]} (if 0.9, modifier not applied)"
        assert torch.allclose(
            components_add["extrinsic"][1], torch.tensor(1.8, device=device)
        ), f"Additive Agent 1: expected 1.8, got {components_add['extrinsic'][1]}"


class TestDeviceMismatch:
    """Test device mismatch detection in calculate_rewards (ENV-007)."""

    def test_meters_device_mismatch_raises(self, bar_index_map_single):
        """calculate_rewards raises RuntimeError when meters on wrong device (ENV-007)."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Create inputs - all correct except meters
        step_counts = torch.zeros(num_agents, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        intrinsic_raw = torch.zeros(num_agents, device=device)

        # Create meters on different "device" (simulate by using meta device concept)
        # Since we can't easily test CPU vs CUDA without CUDA, we mock the device check
        # by creating a tensor and then manually checking the validation logic
        meters = torch.zeros((num_agents, 1), device=device)

        # Test passes normally when all on same device
        total, weights, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )
        assert total.device == device

    def test_device_mismatch_error_message_includes_context(self, bar_index_map_single):
        """Device mismatch error should include both device names for debugging (ENV-007).

        This test verifies the error message format by checking the validation code
        exists and includes helpful device information. Since we can't easily create
        actual device mismatches without CUDA, we verify the structure is in place.
        """
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=1.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Verify the engine has device attribute properly set
        assert engine.device == device, "DACEngine should store device"

        # The actual device mismatch would happen at runtime if tensors
        # were created on different devices (e.g., CPU vs CUDA)
        # The validation code in calculate_rewards will catch this


class TestCompositionControls:
    """Test composition.normalize and composition.clip functionality (BUG-33)."""

    def test_clip_bounds_rewards_within_range(self, bar_index_map_single):
        """Clip bounds should clamp total rewards to [min, max]."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        # Create config with extrinsic strategy that produces large rewards
        # and composition clip bounds
        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=100.0,  # Large base to exceed clip bounds
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=False,
                clip={"min": -1.0, "max": 1.0},  # Strict bounds
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        # Create test data with full energy (should produce reward = 100.0 * 1.0 = 100.0)
        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)  # Full energy
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Verify extrinsic component is large (unclipped)
        assert torch.all(components["extrinsic"] > 10.0), "Extrinsic should be large before clipping"

        # Verify total reward is clipped to [min, max]
        assert torch.all(total_rewards >= -1.0), "All rewards should be >= clip.min"
        assert torch.all(total_rewards <= 1.0), "All rewards should be <= clip.max"
        assert torch.all(total_rewards == 1.0), "With full energy and large base, should be clipped to max=1.0"

    def test_clip_allows_negative_rewards_within_bounds(self, bar_index_map_single):
        """Clip should handle negative rewards correctly."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="constant_base_with_shaped_bonus",
                base_reward=-50.0,  # Large negative base to exceed lower bound
                bar_bonuses=[],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=False,
                clip={"min": -10.0, "max": 10.0},
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Verify extrinsic component is large negative (unclipped)
        assert torch.all(components["extrinsic"] < -10.0), "Extrinsic should be large negative before clipping"

        # Verify total reward is clipped to min bound
        assert torch.all(total_rewards >= -10.0), "All rewards should be >= clip.min"
        assert torch.all(total_rewards <= 10.0), "All rewards should be <= clip.max"
        assert torch.all(total_rewards == -10.0), "With large negative base, should be clipped to min=-10.0"

    def test_normalize_applies_tanh_to_total_reward(self, bar_index_map_single):
        """Normalize should apply tanh to bound rewards to [-1, 1]."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=10.0,  # Large base to test normalization
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=True,  # Enable normalization
                clip=None,
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)  # Full energy
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Verify extrinsic component is large (unnormalized)
        assert torch.all(components["extrinsic"] > 5.0), "Extrinsic should be large before normalization"

        # Verify total reward is bounded to [-1, 1] by tanh
        assert torch.all(total_rewards >= -1.0), "Normalized rewards should be >= -1"
        assert torch.all(total_rewards <= 1.0), "Normalized rewards should be <= 1"

        # Verify tanh was actually applied (for large positive input, tanh ≈ 1.0)
        expected = torch.tanh(components["extrinsic"])  # Since intrinsic and shaping are 0
        assert torch.allclose(total_rewards, expected, atol=1e-6), "Total reward should match tanh(extrinsic)"

    def test_normalize_and_clip_both_apply_in_order(self, bar_index_map_single):
        """When both normalize and clip are enabled, normalize should apply first, then clip."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=100.0,  # Very large base
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=True,  # First: tanh -> bounds to [-1, 1]
                clip={"min": -0.5, "max": 0.5},  # Then: clip to tighter range
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, components = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Extrinsic is large
        assert torch.all(components["extrinsic"] > 10.0), "Extrinsic should be large"

        # After tanh, would be ≈ 1.0
        after_tanh = torch.tanh(components["extrinsic"])
        assert torch.all(after_tanh > 0.99), "tanh(100.0) should be ≈ 1.0"

        # After clip, should be bounded to 0.5
        assert torch.all(total_rewards <= 0.5), "Final rewards should be clipped to max=0.5"
        assert torch.all(total_rewards == 0.5), "With large base, should normalize to ≈1.0 then clip to 0.5"

    def test_clip_none_does_not_clip(self, bar_index_map_single):
        """When clip=None, rewards should not be clipped."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=100.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=False,
                clip=None,  # No clipping
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, _ = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Without clipping, large rewards should pass through
        assert torch.all(total_rewards > 10.0), "Rewards should not be clipped when clip=None"
        assert torch.all(total_rewards == 100.0), "Reward should be 100.0 * 1.0 = 100.0"

    def test_normalize_false_does_not_normalize(self, bar_index_map_single):
        """When normalize=False, rewards should not be normalized."""
        device = torch.device("cpu")
        num_agents = 4

        vfs_registry = VariableRegistry(
            variables=[
                VariableDef(
                    id="energy",
                    scope="agent",
                    type="scalar",
                    default=1.0,
                    readable_by=["agent", "engine"],
                    writable_by=["engine"],
                    lifetime="episode",
                )
            ],
            num_agents=num_agents,
            device=device,
        )

        from townlet.config.drive_as_code import CompositionConfig

        dac_config = DriveAsCodeConfig(
            version="1.0",
            modifiers={},
            extrinsic=ExtrinsicStrategyConfig(
                type="multiplicative",
                base=10.0,
                bars=["energy"],
            ),
            intrinsic=IntrinsicStrategyConfig(strategy="none", base_weight=0.0),
            composition=CompositionConfig(
                normalize=False,  # No normalization
                clip=None,
                log_components=True,
            ),
        )

        engine = DACEngine(dac_config, vfs_registry, device, num_agents, bar_index_map_single)

        step_counts = torch.zeros(num_agents, dtype=torch.long, device=device)
        dones = torch.zeros(num_agents, dtype=torch.bool, device=device)
        meters = torch.ones((num_agents, 1), device=device)
        intrinsic_raw = torch.zeros(num_agents, device=device)

        total_rewards, _, _ = engine.calculate_rewards(
            step_counts=step_counts,
            dones=dones,
            meters=meters,
            intrinsic_raw=intrinsic_raw,
        )

        # Without normalization, large rewards should pass through
        assert torch.all(total_rewards > 1.0), "Rewards should not be normalized when normalize=False"
        assert torch.all(total_rewards == 10.0), "Reward should be 10.0 * 1.0 = 10.0"
