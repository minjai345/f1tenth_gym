"""Typed configuration structures for the simplified F1TENTH gym environment."""
from __future__ import annotations

from dataclasses import dataclass, field, fields, replace
from enum import IntEnum
from typing import TYPE_CHECKING, Any, Callable, Optional

import warnings

import numpy as np

from .integrators import IntegratorType
from .dynamic_models import (
    DynamicModel,
    VehicleParameters,
    VehicleParamRanges,
    F1TENTH_VEHICLE_PARAMETERS,
)
from .action import LongitudinalActionType, SteerActionType
from .observation import ObservationType
from .reset import ReferenceLine, ResetStrategy
from .lidar import LiDARConfig
from .collision_models import CollisionCheckMode

if TYPE_CHECKING:
    from .track import Track

# Type aliases for callables used throughout the simulator
DynamicsFn = Callable[[np.ndarray, np.ndarray, np.ndarray], np.ndarray]
StandardStateFn = Callable[[np.ndarray], np.ndarray]
IntegratorFn = Callable[[DynamicsFn, np.ndarray, np.ndarray, float, np.ndarray], np.ndarray]


class LoopCounterMode(IntEnum):
    """Mode for counting completed laps.

    TOGGLE: Uses start/finish line crossing detection.
    FRENET_BASED: Uses Frenet frame progress along centerline.
    WINDING_ANGLE: Uses cumulative angle around track center.
    """

    TOGGLE = 1
    FRENET_BASED = 2
    WINDING_ANGLE = 3


class RewardMode(IntEnum):
    """How the per-step scalar reward is computed (see ``RewardConfig``).

    - ``SURVIVAL``: reward = timestep (time-alive; the historical default).
    - ``PROGRESS``: weighted sum of forward Frenet arclength progress, speed, a
      survival bonus, and a collision penalty. Needs the Frenet frame.
    - ``CUSTOM``: reward = reward_fn(obs, action, info, terminated, truncated).
    """

    SURVIVAL = 0
    PROGRESS = 1
    CUSTOM = 2


@dataclass(frozen=True)
class ControlConfig:
    """Configuration for vehicle control inputs.

    Attributes:
        longitudinal_mode: How longitudinal control is interpreted (speed or acceleration).
        steering_mode: How steering control is interpreted (angle or angular velocity).
        steer_delay_steps: Number of timesteps to delay steering commands.
        throttle_delay_steps: Number of timesteps to delay longitudinal commands
            (models drivetrain/ESC lag; steering already had its own delay).
        steer_noise_std: Std of Gaussian noise added to the steering command
            each step (actuator/servo noise).
        accl_noise_std: Std of Gaussian noise added to the longitudinal command
            each step.
    """

    longitudinal_mode: LongitudinalActionType = LongitudinalActionType.SPEED
    steering_mode: SteerActionType = SteerActionType.STEERING_ANGLE
    steer_delay_steps: int = 0
    throttle_delay_steps: int = 0
    steer_noise_std: float = 0.0
    accl_noise_std: float = 0.0

    def __post_init__(self) -> None:
        if self.steer_delay_steps < 0:
            raise ValueError(f"steer_delay_steps must be >= 0, got {self.steer_delay_steps}")
        if self.throttle_delay_steps < 0:
            raise ValueError(f"throttle_delay_steps must be >= 0, got {self.throttle_delay_steps}")
        if self.steer_noise_std < 0:
            raise ValueError(f"steer_noise_std must be >= 0, got {self.steer_noise_std}")
        if self.accl_noise_std < 0:
            raise ValueError(f"accl_noise_std must be >= 0, got {self.accl_noise_std}")

    def with_updates(self, **changes: Any) -> "ControlConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class SimulationConfig:
    """Configuration for physics simulation.

    Attributes:
        timestep: Simulation timestep in seconds.
        integrator_timestep: Integration timestep (can be smaller than timestep).
        integrator: Numerical integration method (Euler or RK4).
        dynamics_model: Vehicle dynamics model to use.
        loop_counter: Method for counting completed laps.
        compute_frenet_frame: Whether to compute Frenet frame coordinates.
        max_laps: Maximum laps before episode ends (None for infinite).
    """

    timestep: float = 0.01
    integrator_timestep: float = 0.01
    integrator: IntegratorType = IntegratorType.RK4
    dynamics_model: DynamicModel = DynamicModel.ST
    loop_counter: LoopCounterMode = LoopCounterMode.FRENET_BASED
    compute_frenet_frame: bool = True
    max_laps: Optional[int] = 1

    def __post_init__(self) -> None:
        if self.timestep <= 0:
            raise ValueError(f"timestep must be > 0, got {self.timestep}")
        if self.integrator_timestep <= 0:
            raise ValueError(f"integrator_timestep must be > 0, got {self.integrator_timestep}")
        if self.max_laps is not None and self.max_laps < 1:
            raise ValueError(f"max_laps must be >= 1 or None, got {self.max_laps}")

    def with_updates(self, **changes: Any) -> "SimulationConfig":
        updated = replace(self, **changes)
        if updated.loop_counter is LoopCounterMode.FRENET_BASED and not updated.compute_frenet_frame:
            updated = replace(updated, compute_frenet_frame=True)
        return updated


@dataclass(frozen=True)
class ObservationConfig:
    """Configuration for environment observations.

    Attributes:
        type: Observation format type.
        features: Specific features to include (None for all).
    """

    type: ObservationType = ObservationType.DIRECT
    features: Optional[tuple[str, ...]] = None

    def __post_init__(self) -> None:
        # `features` only affects the FEATURES observation type; every other
        # type uses a fixed preset, so silently ignoring features here hides a
        # config mistake (the user probably meant type=FEATURES).
        if self.features is not None and self.type is not ObservationType.FEATURES:
            raise ValueError(
                f"observation `features` only applies to ObservationType.FEATURES, "
                f"but type={self.type.name}. Use ObservationType.FEATURES to select a "
                f"custom field subset, or drop `features`."
            )

    def with_updates(self, **changes: Any) -> "ObservationConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class ResetConfig:
    """Configuration for episode reset behavior.

    Attributes:
        strategy: Reset strategy for initial agent positions.
        min_dist: Minimum spacing between agents' spawn points, in metres.
            ``None`` = the strategy's default (1.5 for RL, 0.5 for map).
        max_dist: Maximum spacing between agents' spawn points, in metres.
            ``None`` = the strategy's default (2.5 for RL, 1.0 for map).
        shuffle: Override whether agent spawn order is shuffled. ``None`` uses
            the strategy default (STATIC strategies don't shuffle).
        move_laterally: Override whether spawns are offset laterally off the
            reference line. ``None`` uses the strategy default.
        reference_line: Which line the RL_* strategies spawn on. ``None`` =
            ``ReferenceLine.RACELINE`` (today's behaviour); ``CENTERLINE``
            gives ``ey == 0`` at spawn. Not applicable to MAP strategies.
        start_width: Length of the grid strategies' spawn window along the
            reference line, in absolute metres (default 1.0). The window is
            clamped to at least one waypoint, so scaled maps stay legal.
            Only applicable to the two GRID strategies.
    """

    strategy: ResetStrategy = ResetStrategy.RL_GRID_STATIC
    min_dist: Optional[float] = None
    max_dist: Optional[float] = None
    shuffle: Optional[bool] = None
    move_laterally: Optional[bool] = None
    reference_line: Optional[ReferenceLine] = None
    start_width: Optional[float] = None

    def __post_init__(self) -> None:
        if self.min_dist is not None and self.min_dist < 0:
            raise ValueError(f"min_dist must be >= 0, got {self.min_dist}")
        if self.max_dist is not None and self.max_dist <= 0:
            raise ValueError(f"max_dist must be > 0, got {self.max_dist}")
        if (
            self.min_dist is not None
            and self.max_dist is not None
            and self.min_dist >= self.max_dist
        ):
            raise ValueError(
                f"min_dist ({self.min_dist}) must be < max_dist ({self.max_dist})"
            )
        if self.reference_line is not None:
            if not isinstance(self.reference_line, ReferenceLine):
                raise TypeError("reference_line must be a ReferenceLine")
            if self.strategy is ResetStrategy.MAP_RANDOM_STATIC:
                raise ValueError("reference_line does not apply to MAP strategies")
        if self.start_width is not None:
            if self.start_width <= 0:
                raise ValueError(f"start_width must be > 0, got {self.start_width}")
            if self.strategy not in (
                ResetStrategy.RL_GRID_STATIC,
                ResetStrategy.RL_GRID_RANDOM,
            ):
                raise ValueError("start_width only applies to the GRID strategies")

    def reset_kwargs(self) -> dict:
        """Non-None reset params, to forward to ``make_reset_fn``."""
        keys = ("min_dist", "max_dist", "shuffle", "move_laterally", "reference_line", "start_width")
        return {k: getattr(self, k) for k in keys if getattr(self, k) is not None}

    def with_updates(self, **changes: Any) -> "ResetConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class RenderConfig:
    """Configuration for rendering pacing and frame output.

    Rendering is decoupled from stepping: the environment does not own the
    step loop (the user does), so pacing and frame emission are governed by a
    small render clock driven from ``F110Env.render()``. See ``RenderClock``.

    Attributes:
        render_fps: Target fixed frame rate. In human modes this caps redraws
            to at most ``render_fps`` per wall-clock second (so stepping the
            dynamics faster than real time does not force more frames). In
            rgb_array mode it sets the distinct-frame cadence in *sim* time
            (a fresh frame is grabbed every ``1/render_fps`` sim-seconds; the
            cached frame is returned in between). This is NOT the RecordVideo
            container fps -- that stays ``round(1/timestep)`` for real-time
            playback (see ``F110Env``).
        real_time_factor: Sim-seconds simulated per wall-clock second in human
            modes. ``1.0`` = real time, ``5.0`` = 5x faster, ``float("inf")``
            = no pacing (free-run). Ignored in rgb_array mode (never paces).
            Togglable at runtime via ``F110Env.set_real_time_factor``.
        window_size: Square render/frame size in pixels (also the recorded
            rgb_array / video resolution).
        focus_on: Agent id the camera follows (e.g. ``"agent_0"``); ``None`` =
            map view.
        vehicle_palette: Per-agent car colours (hex strings, cycled by index).
        show_wheels: Draw the wheels on each car.
        render_map_img: Draw the occupancy-map image under the scene.
        car_thickness: Car outline thickness in pixels.
        bigger_car_when_map_centered: Scale cars up in the zoomed-out map view.
        show_lap_info: Overlay the lap-time / lap-count label on the frame.

    Rendering uses the OpenGL backend and therefore needs an X display (real or
    a virtual one via ``xvfb``); see ``make_renderer`` for headless/Colab setup.
    """

    render_fps: int = 60
    real_time_factor: float = 1.0
    window_size: int = 800
    focus_on: Optional[str] = "agent_0"
    vehicle_palette: tuple[str, ...] = (
        "#FD3754", "#377eb8", "#984ea3", "#e41a1c", "#ff7f00",
        "#a65628", "#f781bf", "#888888", "#a6cee3", "#b2df8a",
    )
    show_wheels: bool = True
    render_map_img: bool = True
    car_thickness: int = 1
    bigger_car_when_map_centered: bool = True
    show_lap_info: bool = True

    def __post_init__(self) -> None:
        object.__setattr__(self, "render_fps", int(self.render_fps))
        object.__setattr__(self, "real_time_factor", float(self.real_time_factor))
        object.__setattr__(self, "window_size", int(self.window_size))
        object.__setattr__(self, "car_thickness", int(self.car_thickness))
        if self.render_fps <= 0:
            raise ValueError(f"render_fps must be > 0, got {self.render_fps}")
        if not (self.real_time_factor > 0):
            raise ValueError(
                f"real_time_factor must be > 0 (or float('inf')), got {self.real_time_factor}"
            )
        if self.window_size <= 0:
            raise ValueError(f"window_size must be > 0, got {self.window_size}")

    def with_updates(self, **changes: Any) -> "RenderConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class TerminationConfig:
    """Configuration for episode termination and truncation.

    Attributes:
        max_episode_steps: If set, the episode is truncated (``truncated=True``)
            once this many steps have elapsed since reset. ``None`` = no limit.
        terminate_on_collision: Whether a collision ends the episode
            (``terminated=True``).
        collision_agents: Whose collisions count when ``terminate_on_collision``
            is set: ``"ego"`` (only the ego agent) or ``"any"`` (any agent).
    """

    max_episode_steps: Optional[int] = None
    terminate_on_collision: bool = True
    collision_agents: str = "ego"

    def __post_init__(self) -> None:
        if self.max_episode_steps is not None and self.max_episode_steps < 1:
            raise ValueError(
                f"max_episode_steps must be >= 1 or None, got {self.max_episode_steps}"
            )
        if self.collision_agents not in ("ego", "any"):
            raise ValueError(
                f"collision_agents must be 'ego' or 'any', got {self.collision_agents!r}"
            )

    def with_updates(self, **changes: Any) -> "TerminationConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class RewardConfig:
    """Configuration for the per-step scalar reward.

    Whatever the mode, ``info`` always carries the raw signals (``progress`` =
    per-agent forward Frenet arclength this step, ``collisions`` = per-agent
    flags) so external code (e.g. f1tenth_learning) can compute any reward.

    Attributes:
        mode: RewardMode (SURVIVAL / PROGRESS / CUSTOM). Default SURVIVAL keeps
            the historical ``reward = timestep``.
        progress_weight: reward per metre of forward arclength (PROGRESS mode).
        velocity_weight: reward per m/s of ego speed (PROGRESS mode).
        timestep_weight: survival bonus per step, scaled by timestep (PROGRESS).
        collision_penalty: subtracted on a step where the ego is colliding
            (PROGRESS mode); must be >= 0.
        reward_fn: for CUSTOM mode, a callable
            ``(obs, action, info, terminated, truncated) -> float``.
    """

    mode: RewardMode = RewardMode.SURVIVAL
    progress_weight: float = 1.0
    velocity_weight: float = 0.0
    timestep_weight: float = 0.0
    collision_penalty: float = 0.0
    reward_fn: Optional[Callable] = None

    def __post_init__(self) -> None:
        if self.collision_penalty < 0:
            raise ValueError(f"collision_penalty must be >= 0, got {self.collision_penalty}")
        if self.mode is RewardMode.CUSTOM and self.reward_fn is None:
            raise ValueError("RewardMode.CUSTOM requires reward_fn to be set")
        if self.reward_fn is not None and not callable(self.reward_fn):
            raise TypeError("reward_fn must be callable")

    def with_updates(self, **changes: Any) -> "RewardConfig":
        return replace(self, **changes)


@dataclass(frozen=True)
class DomainRandomizationConfig:
    """Per-episode randomization of vehicle parameters, applied at ``reset()``.

    ``param_ranges`` is a :class:`VehicleParamRanges` giving an ABSOLUTE
    ``(low, high)`` range in physical units per field; each set field is
    sampled uniformly at every reset from the env RNG (so it is reproducible
    with ``reset(seed=...)``). Only set fields are randomized. Example::

        DomainRandomizationConfig(enabled=True, param_ranges=VehicleParamRanges(
            m=(3.0, 4.0), mu=(0.9, 1.1), lf=(0.14, 0.18),
        ))

    A plain ``{name: (low, high)}`` dict is still accepted for one release
    (deprecated). Field names are the actual ``VehicleParameters`` fields,
    e.g. ``m`` (mass) and ``h`` (CoG height) -- not ``mass``/``h_cg``. Prefer
    randomizing *dynamics* params (m, mu, lf, lr, I, h). Randomizing the
    actuation limits (v_min/v_max/s_min/s_max/...) is supported: the spaces
    are built from :meth:`widest_params`, a fixed superset of every episode.

    Attributes:
        enabled: Whether to randomize at each reset.
        param_ranges: ``VehicleParamRanges`` (or a deprecated dict) of
            absolute ``(low, high)`` ranges.
    """

    enabled: bool = False
    param_ranges: VehicleParamRanges | dict = field(default_factory=dict)

    def __post_init__(self) -> None:
        if isinstance(self.param_ranges, dict):
            if self.param_ranges:
                warnings.warn(
                    "dict param_ranges is deprecated; pass a VehicleParamRanges",
                    DeprecationWarning,
                    stacklevel=3,
                )
        elif not isinstance(self.param_ranges, VehicleParamRanges):
            raise TypeError("param_ranges must be a VehicleParamRanges (or a deprecated dict)")
        valid = {f.name for f in fields(VehicleParameters)}
        for name, rng in self.ranges().items():
            if name not in valid:
                raise ValueError(
                    f"unknown vehicle parameter {name!r} in param_ranges "
                    f"(must be a VehicleParameters field)"
                )
            if len(rng) != 2 or float(rng[0]) > float(rng[1]):
                raise ValueError(
                    f"param_ranges[{name!r}] must be (low, high) with low <= high, got {rng!r}"
                )

    def ranges(self) -> dict:
        """The active ranges as a plain ``{name: (low, high)}`` dict."""
        if isinstance(self.param_ranges, VehicleParamRanges):
            return self.param_ranges.as_dict()
        return dict(self.param_ranges)

    def widest_params(self, base: VehicleParameters) -> VehicleParameters:
        """``base`` with each randomized *limit* field at its widest extreme.

        Spaces built from the result are a fixed valid superset of every
        randomized episode (gymnasium requires fixed spaces). With DR disabled
        this returns ``base`` unchanged, so spaces are byte-identical to a
        non-DR env.
        """
        if not self.enabled:
            return base
        changes = {}
        for name, (lo, hi) in self.ranges().items():
            if name in _WIDEN_AT_LOW:
                changes[name] = float(lo)
            elif name in _WIDEN_AT_HIGH:
                changes[name] = float(hi)
        return base.with_updates(**changes) if changes else base

    def with_updates(self, **changes: Any) -> "DomainRandomizationConfig":
        return replace(self, **changes)


# Which extreme of a randomized range widens the space built from it. Params
# in neither table (m, mu, I, h, ...) don't feed any space bound.
_WIDEN_AT_LOW = ("v_min", "s_min", "sv_min", "lf", "lr")   # shorter wheelbase -> higher yaw-rate cap
_WIDEN_AT_HIGH = ("v_max", "s_max", "sv_max", "a_max")


@dataclass(frozen=True)
class EnvConfig:
    """Main configuration for the F1TENTH environment.

    Attributes:
        seed: Optional seed making a whole run deterministic: the first
            unseeded ``reset()`` behaves as ``reset(seed=seed)``, and every
            later unseeded reset continues that stream. An explicit
            ``reset(seed=...)`` always wins. ``None`` (default) seeds from OS
            entropy. Caution: vectorized sub-envs sharing one config share the
            seed and will produce identical rollouts — seed per sub-env there.
        map_name: Track name, path, or Track instance.
        map_scale: Scale factor for the map.
        params: Vehicle physical parameters.
        num_agents: Number of agents in the environment.
        ego_index: Index of the ego agent (0-indexed).
        control_config: Control input configuration.
        simulation_config: Physics simulation configuration.
        observation_config: Observation space configuration.
        reset_config: Episode reset configuration.
        lidar_config: LiDAR sensor configuration.
        render_config: Rendering pacing / frame-output configuration.
        termination_config: Episode termination / truncation configuration.
        reward_config: Per-step reward configuration.
        domain_randomization_config: Per-episode vehicle-param randomization.
        collision_check: Collision detection mode.
        render_enabled: Whether rendering is enabled.
    """

    seed: Optional[int] = None
    map_name: "Track | str" = "Spielberg"
    map_scale: float = 1.0
    params: VehicleParameters = F1TENTH_VEHICLE_PARAMETERS
    num_agents: int = 1
    ego_index: int = 0
    control_config: ControlConfig = field(default_factory=ControlConfig)
    simulation_config: SimulationConfig = field(default_factory=SimulationConfig)
    observation_config: ObservationConfig = field(default_factory=ObservationConfig)
    reset_config: ResetConfig = field(default_factory=ResetConfig)
    lidar_config: LiDARConfig = field(default_factory=LiDARConfig)
    render_config: RenderConfig = field(default_factory=RenderConfig)
    termination_config: TerminationConfig = field(default_factory=TerminationConfig)
    reward_config: RewardConfig = field(default_factory=RewardConfig)
    domain_randomization_config: DomainRandomizationConfig = field(
        default_factory=DomainRandomizationConfig
    )
    collision_check: CollisionCheckMode = CollisionCheckMode.LIDAR_SCAN
    render_enabled: bool = True

    def __post_init__(self) -> None:
        if not isinstance(self.params, VehicleParameters):
            raise TypeError("params must be a VehicleParameters instance")

        if self.seed is not None:
            object.__setattr__(self, "seed", int(self.seed))
        object.__setattr__(self, "map_scale", float(self.map_scale))
        object.__setattr__(self, "num_agents", int(self.num_agents))
        object.__setattr__(self, "ego_index", int(self.ego_index))
        object.__setattr__(self, "render_enabled", bool(self.render_enabled))

        # Validate numeric constraints
        if self.map_scale <= 0:
            raise ValueError(f"map_scale must be > 0, got {self.map_scale}")
        if self.num_agents < 1:
            raise ValueError(f"num_agents must be >= 1, got {self.num_agents}")
        if not (0 <= self.ego_index < self.num_agents):
            raise ValueError(
                f"ego_index must be in range [0, num_agents), got {self.ego_index} with num_agents={self.num_agents}"
            )

        control_cfg = self.control_config
        if not isinstance(control_cfg, ControlConfig):
            raise TypeError("control must be a ControlConfig instance")

        simulation_cfg = self.simulation_config
        if not isinstance(simulation_cfg, SimulationConfig):
            raise TypeError("simulation must be a SimulationConfig instance")

        observation_cfg = self.observation_config
        if not isinstance(observation_cfg, ObservationConfig):
            raise TypeError("observation must be an ObservationConfig instance")

        reset_cfg = self.reset_config
        if not isinstance(reset_cfg, ResetConfig):
            raise TypeError("reset must be a ResetConfig instance")

        lidar_cfg = self.lidar_config
        if not isinstance(lidar_cfg, LiDARConfig):
            raise TypeError("lidar must be a LiDARConfig instance")

        render_cfg = self.render_config
        if not isinstance(render_cfg, RenderConfig):
            raise TypeError("render must be a RenderConfig instance")

        termination_cfg = self.termination_config
        if not isinstance(termination_cfg, TerminationConfig):
            raise TypeError("termination must be a TerminationConfig instance")

        reward_cfg = self.reward_config
        if not isinstance(reward_cfg, RewardConfig):
            raise TypeError("reward must be a RewardConfig instance")
        if reward_cfg.mode is RewardMode.PROGRESS and not simulation_cfg.compute_frenet_frame:
            raise ValueError(
                "RewardMode.PROGRESS needs the Frenet frame; set "
                "simulation_config.compute_frenet_frame=True"
            )

        dr_cfg = self.domain_randomization_config
        if not isinstance(dr_cfg, DomainRandomizationConfig):
            raise TypeError("domain_randomization must be a DomainRandomizationConfig instance")

        # The multi-body model needs the full 87-parameter ABI. The two small-scale
        # presets leave all 69 multi-body fields at nan, which produced a NaN state
        # with no error rather than a trajectory. Fail here instead, before the map
        # download and the JIT.
        if simulation_cfg.dynamics_model is DynamicModel.MB:
            missing = self.params.missing_mb_parameters()
            if missing:
                raise ValueError(
                    f"DynamicModel.MB needs the multi-body parameters, but "
                    f"{len(missing)} are not finite (e.g. {', '.join(missing[:4])}). "
                    f"Use FULLSCALE_VEHICLE_PARAMETERS, which is the only preset that "
                    f"populates them, or supply your own values."
                )

        if (
            simulation_cfg.loop_counter is LoopCounterMode.FRENET_BASED
            and not simulation_cfg.compute_frenet_frame
        ):
            simulation_cfg = simulation_cfg.with_updates(compute_frenet_frame=True)

        object.__setattr__(self, "control_config", control_cfg)
        object.__setattr__(self, "simulation_config", simulation_cfg)
        object.__setattr__(self, "observation_config", observation_cfg)
        object.__setattr__(self, "reset_config", reset_cfg)
        object.__setattr__(self, "lidar_config", lidar_cfg)
        object.__setattr__(self, "render_config", render_cfg)
        object.__setattr__(self, "termination_config", termination_cfg)
        object.__setattr__(self, "reward_config", reward_cfg)
        object.__setattr__(self, "domain_randomization_config", dr_cfg)

    def with_updates(self, **changes: Any) -> "EnvConfig":
        return replace(self, **changes)