# Copyright 2025 The HuggingFace Inc. team. All rights reserved.
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
#     http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

"""Local asynchronous RTC prediction with serialized policy and processor ownership."""

from __future__ import annotations

import inspect
import logging
import math
import time
import traceback
from collections.abc import Callable, Mapping
from copy import deepcopy
from dataclasses import asdict, dataclass, field
from threading import Event, Lock, Thread
from typing import Any

import torch

from lerobot.policies import ActionQueue, PreTrainedPolicy, RTCConfig, prepare_observation_for_inference
from lerobot.policies.rtc.configuration_rtc import validate_trained_rtc_horizon
from lerobot.processor import (
    NormalizerProcessorStep,
    PolicyProcessorPipeline,
    RelativeActionsProcessorStep,
    RelativeEEActionsStep,
)
from lerobot.utils.feature_utils import build_dataset_frame

from .base import InferenceEngine, InferenceRobot, PolicyQuery
from .contracts import (
    DEFAULT_MAX_TEXT_OUTPUT_CHARS,
    ActionChunk,
    ActionProvenance,
    ChunkPolicySpec,
    ExecutionMode,
    ObservationSnapshot,
    QueryKind,
)
from .execution import ChunkRuntime, HoldState
from .prediction import ChunkPrediction, chunk_inference_context, predict_chunk

logger = logging.getLogger(__name__)

# How long the RTC loop sleeps when paused, idle, or backpressured by a full queue.
_RTC_IDLE_SLEEP_S: float = 0.01
# Consecutive unusable trained-RTC chunks tolerated before declaring the delay unsupportable.
_RTC_MAX_CONSECUTIVE_DISCARDS: int = 5
# Hard timeout for joining the RTC thread on stop().
_RTC_JOIN_TIMEOUT_S: float = 3.0


@dataclass
class _CompilePreparation:
    observation: dict[str, Any]
    task: str
    cancelled: Event = field(default_factory=Event)
    done: Event = field(default_factory=Event)
    error: BaseException | None = None


class _TrainedRTCDelayExceededError(RuntimeError):
    """Raised when measured latency persistently exceeds a trained RTC checkpoint's support."""


# ---------------------------------------------------------------------------
# RTC helpers
# ---------------------------------------------------------------------------


def validate_local_chunk_policy(policy: PreTrainedPolicy) -> ChunkPolicySpec:
    """Check local asynchronous compatibility before connecting hardware or starting a worker."""
    try:
        spec = policy.chunk_inference_spec()
        if not spec.current_observation_only:
            raise ValueError("Local asynchronous inference does not implement temporal observation sampling")
    except (ValueError, NotImplementedError) as exc:
        raise ValueError(
            f"{type(policy).__name__} cannot run with local asynchronous inference: {exc} "
            "Use '--inference.type=sync' for the policy's synchronous execution path."
        ) from exc
    return spec


def supports_rtc_inference(policy: PreTrainedPolicy) -> bool:
    """Whether a policy declares RTC support and accepts the RTC call shape."""
    supports_rtc = getattr(policy, "supports_rtc", None)
    if not callable(supports_rtc) or not supports_rtc():
        return False

    try:
        inspect.signature(policy.predict_action_chunk).bind(
            object(),
            inference_delay=0,
            prev_chunk_left_over=None,
        )
    except (TypeError, ValueError):
        return False
    return True


# ---------------------------------------------------------------------------
# RTCInferenceEngine
# ---------------------------------------------------------------------------


class RTCInferenceEngine(InferenceEngine):
    """Background RTC prediction with control-thread capture and action consumption.

    Notify each capture; pause/resume around intervention and honor dispatch gates.
    """

    def __init__(
        self,
        policy: PreTrainedPolicy,
        preprocessor: PolicyProcessorPipeline,
        postprocessor: PolicyProcessorPipeline,
        robot_wrapper: InferenceRobot,
        rtc_config: RTCConfig,
        dataset_features: dict,
        task: str,
        fps: float,
        device: str | None,
        use_torch_compile: bool = False,
        compile_warmup_inferences: int = 2,
        rtc_queue_threshold: int = 30,
        shutdown_event: Event | None = None,
        max_observation_age_s: float = 5.0,
        action_timeout_s: float = 10.0,
        startup_timeout_s: float = 120.0,
        language_timeout_s: float = 120.0,
        action_starvation_grace_s: float = 1.0,
    ) -> None:
        """Own local asynchronous policy work and configure supported waiting."""
        super().__init__(task=task)
        self._policy = policy
        self._policy_spec = validate_local_chunk_policy(policy)
        self._preprocessor = preprocessor
        self._postprocessor = postprocessor
        self._model_action_dim: int | None = None
        action_feature = getattr(policy.config, "action_feature", None)
        self._canonical_action_dim = (
            action_feature.shape[0] if action_feature is not None else len(robot_wrapper.action_features)
        )
        if "action" in dataset_features:
            self._canonical_action_dim = dataset_features["action"]["shape"][0]
        self._robot = robot_wrapper
        self._rtc_config = rtc_config
        # Same feature spec sync uses, so both engines order observation.state identically.
        self._obs_features = dataset_features
        self._fps = fps
        self._device = device or "cpu"
        self._use_torch_compile = use_torch_compile
        minimum_warmup = 3 if rtc_config.enabled else 1
        self._compile_warmup_inferences = max(minimum_warmup, compile_warmup_inferences)
        self._rtc_queue_threshold = rtc_queue_threshold
        if not math.isfinite(language_timeout_s) or language_timeout_s <= 0:
            raise ValueError("Language deadline must be finite and positive")
        self._language_timeout_s = language_timeout_s
        self._action_timeout_s = action_timeout_s
        mode = ExecutionMode(f"rtc_{rtc_config.mode}") if rtc_config.enabled else ExecutionMode.CHUNK
        if mode not in self._policy_spec.modes:
            raise ValueError(f"Policy does not support asynchronous execution mode {mode.value!r}")
        self._runtime = ChunkRuntime(
            mode=mode,
            action_interval=1 / fps,
            refill_seconds=max(0, rtc_queue_threshold) / fps,
            max_observation_age_s=max_observation_age_s,
            # Cold compilation uses the startup budget; it is not an ordinary
            # action-latency measurement or a steady-state request deadline.
            action_timeout_s=startup_timeout_s if use_torch_compile else action_timeout_s,
            startup_timeout_s=startup_timeout_s,
            action_starvation_grace_s=action_starvation_grace_s,
            training_max_delay=self._policy_spec.training_max_delay,
        )
        self._runtime.queue.cfg = rtc_config
        self._reset_pending = False
        self._pending_rtc_tuning: dict[str, Any] | None = None
        self._hold = HoldState()
        self._active_query_generation = 0
        for step in preprocessor.steps:
            if isinstance(step, RelativeActionsProcessorStep):
                step.bind_action_queue(None)
        self._language_preprocessor = deepcopy(preprocessor)
        if getattr(robot_wrapper, "supports_position_hold", False):
            robot_wrapper.configure_position_hold()
        if not getattr(robot_wrapper, "supports_hold", False):
            self._runtime.starvation_grace = 0.0
            if action_starvation_grace_s:
                logger.warning(
                    "Local RTC action-starvation grace is unavailable without supported robot hold; "
                    "buffer exhaustion remains terminal"
                )

        self._obs_holder: dict[str, Any] = {}
        self._obs_lock = Lock()
        # Bumped by reset() under _obs_lock, so a chunk whose inference started before a
        # reset is discarded instead of merged into the fresh queue.
        self._reset_epoch = 0
        self._policy_active = Event()
        self._compile_warmup_done = Event()
        self._shutdown_event = Event()
        self._rtc_error = Event()
        self._failure_traceback: str | None = None
        self._global_shutdown_event = shutdown_event
        self._rtc_thread: Thread | None = None
        self._started = False
        self._compile_preparation: _CompilePreparation | None = None

        if not self._use_torch_compile:
            self._compile_warmup_done.set()
            logger.info("RTCInferenceEngine initialized (torch.compile disabled, no warmup needed)")
        else:
            logger.info(
                "RTCInferenceEngine initialized (torch.compile enabled, %d warmup inferences)",
                self._compile_warmup_inferences,
            )

        # Processor introspection for relative-action re-anchoring.
        self._relative_step = next(
            (
                s
                for s in preprocessor.steps
                if isinstance(s, RelativeActionsProcessorStep)
                and not isinstance(s, RelativeEEActionsStep)
                and s.enabled
            ),
            None,
        )
        self._relative_ee_step = next(
            (s for s in preprocessor.steps if isinstance(s, RelativeEEActionsStep) and s.enabled),
            None,
        )
        self._normalizer_step = next(
            (s for s in preprocessor.steps if isinstance(s, NormalizerProcessorStep)),
            None,
        )
        if self._relative_step is not None:
            if self._relative_step.action_names is None:
                cfg_names = getattr(policy.config, "action_feature_names", None)
                if cfg_names:
                    self._relative_step.action_names = list(cfg_names)
                else:
                    self._relative_step.action_names = [
                        k for k in robot_wrapper.action_features if k.endswith(".pos")
                    ]
            logger.info("Relative actions enabled: RTC prefix will be re-anchored")

        if self._relative_ee_step is not None:
            logger.info("Relative EE enabled: RTC prefix will be re-anchored in SE(3)")

    # ------------------------------------------------------------------
    # Lifecycle
    # ------------------------------------------------------------------

    @property
    def ready(self) -> bool:
        """True once torch.compile warmup is complete (or immediately if compile is disabled)."""
        return self._compile_warmup_done.is_set()

    @property
    def failed(self) -> bool:
        """True if the RTC background thread exited due to an unrecoverable error."""
        return self._rtc_error.is_set() or self._runtime.failure is not None

    @property
    def failure_traceback(self) -> str | None:
        """Traceback captured when the RTC thread died (see ``failed``).

        Kept as data, not just logged, so consumers can re-surface it when someone looks.
        """
        return self._failure_traceback or self._runtime.failure

    @property
    def action_queue(self) -> ActionQueue:
        """The shared action queue between the RTC thread and the main loop."""
        return self._runtime.queue

    def prepare_compilation(
        self, obs: dict, *, timeout_s: float, cancelled: Callable[[], bool] | None = None
    ) -> None:
        """Warm representative call shapes on the worker while execution stays paused.

        The owned snapshot is for compilation only. Its predictions never enter the
        runtime queue, and no synthetic fresh timestamp is assigned to old images.
        Cancellation cannot interrupt a model call already inside the compiler.
        """
        if not math.isfinite(timeout_s) or timeout_s <= 0:
            raise ValueError("Compilation timeout must be finite and positive")
        if self.failed:
            raise RuntimeError(f"Inference failed: {self.failure_traceback}")
        if self.ready:
            return
        if self._rtc_thread is None or not self._rtc_thread.is_alive():
            raise RuntimeError("Start the inference worker before preparing compilation")
        job = _CompilePreparation(deepcopy(obs), self.task)
        with self._obs_lock:
            if self._policy_active.is_set():
                raise RuntimeError("Pause inference before preparing compilation")
            if self._compile_preparation is not None:
                raise RuntimeError("Compilation preparation is already running")
            self._compile_preparation = job
        deadline = time.monotonic() + timeout_s
        while not job.done.wait(0.05):
            if self._shutdown_event.is_set() or (cancelled is not None and cancelled()):
                job.cancelled.set()
                raise InterruptedError("Compilation preparation cancelled; no trial started")
            if time.monotonic() >= deadline:
                job.cancelled.set()
                raise TimeoutError("Compilation preparation exceeded its startup timeout")
            if self.failed:
                raise RuntimeError(f"Inference failed: {self.failure_traceback}")
        if job.error is not None:
            raise RuntimeError("Compilation preparation failed") from job.error
        if job.cancelled.is_set() or (cancelled is not None and cancelled()):
            raise InterruptedError("Compilation preparation cancelled; no trial started")

    def _prepare_compile_snapshot(self, job: _CompilePreparation) -> None:
        """Run only on the inference worker; never activate or publish to runtime."""
        previous = canonical_previous = None
        completed = False
        try:
            frame = build_dataset_frame(self._obs_features, job.observation, prefix="observation")
            for index in range(self._compile_warmup_inferences):
                if job.cancelled.is_set() or self._shutdown_event.is_set():
                    return
                delay = 1 if index >= 2 and self._rtc_config.enabled else 0
                if self._runtime.mode is ExecutionMode.RTC_TRAINED and delay:
                    delay = min(self._policy_spec.training_max_delay, self._rtc_config.execution_horizon)
                prediction = self._predict_observation(
                    frame, job.task, self._runtime.mode, previous, canonical_previous, delay
                )
                if self._rtc_config.enabled:
                    # The shared prediction helper normalizes prefixes to this horizon.
                    horizon = self._rtc_config.execution_horizon
                    previous = prediction.model_actions[-horizon:]
                    canonical_previous = prediction.canonical_actions[-horizon:]
                logger.info("Compilation warmup %d/%d complete", index + 1, self._compile_warmup_inferences)
            if not job.cancelled.is_set() and not self._shutdown_event.is_set():
                with self._runtime.lock:
                    self._runtime.action_timeout = self._action_timeout_s
                completed = True
        except Exception as exc:
            job.error = exc
        finally:
            try:
                self._policy.reset()
                self._preprocessor.reset()
                self._postprocessor.reset()
                self._language_preprocessor.reset()
            except Exception as exc:
                job.error = job.error or exc
            if (
                completed
                and job.error is None
                and not job.cancelled.is_set()
                and not self._shutdown_event.is_set()
            ):
                self._compile_warmup_done.set()
            else:
                self._compile_warmup_done.clear()
            with self._obs_lock:
                self._compile_preparation = None
            job.done.set()

    def _predict_observation(
        self,
        features: Mapping[str, Any],
        task: str,
        mode: ExecutionMode,
        previous: torch.Tensor | None,
        canonical_previous: torch.Tensor | None,
        delay: int,
    ) -> ChunkPrediction:
        policy_device = torch.device(self._device)
        batch = prepare_observation_for_inference(
            {key: value.copy() for key, value in features.items()},
            policy_device,
            task,
            self._robot.robot_type,
        )
        batch["task"] = [task]
        with chunk_inference_context(mode):
            prediction = predict_chunk(
                self._policy,
                self._postprocessor,
                self._preprocessor(batch),
                spec=self._policy_spec,
                mode=mode,
                canonical_action_dim=self._canonical_action_dim,
                model_action_dim=self._model_action_dim,
                device=policy_device,
                rtc_horizon=self._rtc_config.execution_horizon if self._rtc_config.enabled else 0,
                inference_delay=delay,
                model_continuation=previous,
                canonical_continuation=canonical_previous,
                relative_step=self._relative_step,
                relative_ee_step=self._relative_ee_step,
                normalizer_step=self._normalizer_step,
            )
            self._model_action_dim = prediction.model_actions.shape[1]
            return prediction

    def start(self) -> None:
        """Launch the RTC background thread."""
        if self._started:
            raise RuntimeError("RTC inference engines cannot be restarted; create a new session")
        self._started = True
        self._runtime.invalidate()
        self._obs_holder = {"obs": None}
        self._shutdown_event.clear()
        self._rtc_thread = Thread(
            target=self._rtc_loop,
            daemon=True,
            name="RTCInference",
        )
        self._rtc_thread.start()
        logger.info("RTC inference thread started")

    def stop(self) -> None:
        """Signal the RTC thread to stop and wait for it."""
        logger.info("Stopping RTC inference thread...")
        self._shutdown_event.set()
        self._policy_active.clear()
        self._runtime.deactivate()
        if self._rtc_thread is not None and self._rtc_thread.is_alive():
            self._rtc_thread.join(timeout=_RTC_JOIN_TIMEOUT_S)
            if self._rtc_thread.is_alive():
                logger.warning("RTC thread did not join within %.1fs", _RTC_JOIN_TIMEOUT_S)
            else:
                logger.info("RTC inference thread stopped")
            self._rtc_thread = None

    def pause(self) -> None:
        """Pause the RTC background thread."""
        logger.info("Pausing RTC inference thread")
        self._policy_active.clear()
        self.drop_pending_query()
        self._runtime.deactivate()
        with self._obs_lock:
            self._reset_epoch += 1
            self._obs_holder["obs"] = None
            self._hold.clear()

    def resume(self) -> None:
        """Resume the RTC background thread."""
        logger.info("Resuming RTC inference thread")
        with self._obs_lock:
            if self._compile_preparation is not None:
                raise RuntimeError("Wait for compilation preparation before resuming inference")
            if self._runtime.activate(held=self._hold.requested):
                self._policy_active.set()

    def set_task(self, task: str) -> bool:
        """Retarget an in-flight prediction through a planned hold when supported.

        Old-task results remain invalid. Without a supported local hold, ordinary
        local RTC retains its buffer/deadline limits and may exhaust on retarget.
        """
        with self._task_lock:
            if task == self._task:
                return False
            previous, self._task = self._task, task
            self._task_changed = True
            self._task_version += 1
            with self._obs_lock, self._runtime.lock:
                pending = self._runtime.pending
                # Warmup queues no motion and its control loop cannot acknowledge a hold.
                needs_hold = (
                    pending is not None
                    and pending.observation.task_version != self._task_version
                    and self._policy_active.is_set()
                    and self.ready
                    and bool(getattr(self._robot, "supports_hold", False))
                )
            # Keep the task lock through invalidation so an old result cannot be
            # accepted while the control thread is transitioning to its hold.
            if needs_hold:
                self._request_hold("Instruction change", self._action_timeout_s)
        logger.info("Task changed: '%s' -> '%s'", previous, task)
        return True

    @property
    def rtc_tuning(self) -> dict[str, Any]:
        """RTC settings and queue threshold, including an update the worker has not applied yet."""
        with self._obs_lock:
            pending = dict(self._pending_rtc_tuning or {})
        return {**asdict(self._rtc_config), **pending, "queue_threshold": self._rtc_queue_threshold}

    def update_rtc_tuning(self, *, queue_threshold: int, **rtc_fields: Any) -> None:
        """Retune a paused engine between runs without restarting the worker.

        The queue threshold applies now; it never enters compiled code. RTC fields apply on
        the worker before its next model call, so no call mixes old and new settings. With
        torch.compile, a changed field clears readiness until warmup runs again.
        """
        cfg, spec, steps = self._rtc_config, self._policy_spec, self._policy_spec.prediction_steps
        tunable = {"execution_horizon", "max_guidance_weight", "prefix_attention_schedule"}
        horizon = rtc_fields.get("execution_horizon", cfg.execution_horizon)
        weight = rtc_fields.get("max_guidance_weight", cfg.max_guidance_weight)
        if self._policy_active.is_set() or self.failed:
            raise RuntimeError("RTC tuning requires a healthy paused engine")
        if not set(rtc_fields) <= tunable:
            raise ValueError(f"Only {sorted(tunable)} can change without a restart")
        if not cfg.enabled or getattr(self._policy.config, "rtc_config", None) is not cfg:
            raise RuntimeError("RTC tuning needs RTC enabled and one config shared with the policy")
        if not 0 < horizon <= steps or not 0 <= queue_threshold <= steps:
            raise ValueError(f"execution_horizon must be in 1..{steps} and queue_threshold in 0..{steps}")
        if not math.isfinite(weight) or weight <= 0:
            raise ValueError("max_guidance_weight must be finite and positive")
        if cfg.mode == "trained":
            validate_trained_rtc_horizon(horizon, steps, spec.training_max_delay)
            if queue_threshold < spec.training_max_delay:
                raise ValueError("queue_threshold must cover rtc_training_max_delay")
        changed = any(getattr(cfg, name) != value for name, value in rtc_fields.items())
        with self._obs_lock, self._runtime.lock:
            self._pending_rtc_tuning = rtc_fields
            self._rtc_queue_threshold = queue_threshold
            self._runtime.refill_seconds = queue_threshold / self._fps
        if changed and self._use_torch_compile:
            self._compile_warmup_done.clear()
        self.reset()  # The worker applies the pending fields while handling this reset.

    def reset(self) -> None:
        """Reset policy, processors, action queue, and inference timing history.

        Safe to call with the RTC thread paused or running.  Also drops the last published
        observation — a chunk computed from a stale one would jerk the robot toward an old
        pose — and bumps the reset epoch so an in-flight chunk is discarded instead of
        merged into the cleared queue.
        """
        logger.info("Resetting RTC inference state (policy + processors + queue)")
        self.drop_pending_query()
        with self._obs_lock:
            # Clear and bump in one critical section, mirroring _rtc_loop's epoch
            # check-and-merge, so a reset cannot leak a pre-reset chunk into the fresh
            # queue.  Lock order is _obs_lock -> queue.lock on both sides.
            self._runtime.invalidate(reset_timing=True)
            self._obs_holder["obs"] = None
            self._reset_epoch += 1
            self._reset_pending = True
            self._hold.clear()
        # The queue is empty, so a pending task change has nothing stale to blend against.
        self._discard_task_change()

    # ------------------------------------------------------------------
    # Action production (called from main thread)
    # ------------------------------------------------------------------

    def get_action(self, obs_frame: dict | None) -> torch.Tensor | None:
        """Pop the next action from the RTC queue (ignores ``obs_frame``)."""
        queued = self._runtime.pop()
        if self._runtime.starvation_deadline is not None and self._runtime.held:
            self._request_hold("Action starvation", self._runtime.starvation_grace)
        if queued is None:
            return None
        action, provenance = queued
        self._set_dispatched_task(provenance.task)
        return action

    def notify_observation(self, obs: dict) -> None:
        """Publish an owned snapshot and its original control-thread capture time."""
        captured_at = getattr(self._robot, "observation_time", None)
        if captured_at is None:
            captured_at = time.monotonic()
        owned = deepcopy(obs)
        with self._obs_lock:
            self._obs_holder["obs"] = owned
            self._obs_holder["capture_time"] = captured_at

    def dispatch_allowed(self) -> bool:
        """Revoke dispatch on every motor tick, including interpolation-only ticks."""
        if self.has_pending_query and self._policy_active.is_set():
            self._request_language_hold()
        with self._obs_lock:
            if self._hold.expired(self._runtime.clock()):
                self._runtime.fault(f"{self._hold.reason} deadline exceeded; restart the inference session")
        permitted = self._runtime.dispatch_allowed()
        return permitted and self.ready and not self._hold.requested

    def acknowledge_hold(self) -> None:
        """Let the worker submit text only after the control thread held the robot."""
        with self._obs_lock:
            if self._hold.acknowledge():
                self._obs_holder["obs"] = None
                self._runtime.acknowledge_starvation_hold()
        if self.failed and self._global_shutdown_event is not None:
            self._global_shutdown_event.set()

    def _request_language_hold(self) -> None:
        self._request_hold("Language request", self._language_timeout_s)

    def _request_hold(self, reason: str, timeout_s: float) -> None:
        with self._obs_lock:
            if not self._hold.request(
                reason,
                self._runtime.clock(),
                None if reason == "Action starvation" else timeout_s,
                upgrade=reason == "Language request",
            ):
                return
            if reason != "Action starvation":
                self._runtime.invalidate(held=True, preserve_starvation=True)

    # ------------------------------------------------------------------
    # Text queries
    # ------------------------------------------------------------------

    @property
    def supports_text_queries(self) -> bool:
        """True with an external text backend, or a policy text head plus a local position hold."""
        return super().supports_text_queries or (
            self._policy.supports_text_generation() and bool(getattr(self._robot, "supports_hold", False))
        )

    def _queue_query(self, query: PolicyQuery) -> bool:
        if self._policy.supports_text_generation() and not getattr(self._robot, "supports_hold", False):
            logger.warning("Local RTC text queries require a supported robot position hold")
            return False
        if not self.supports_text_queries or self.failed:
            return False
        queued = super()._queue_query(query)
        if queued and self._policy_active.is_set():
            self._request_language_hold()
        return queued

    def start_autosteer(self, goal: str, interval_s: float) -> None:
        """Only enable language scheduling when its planned local hold is supported."""
        if not self.supports_text_queries:
            raise ValueError("Local RTC autosteering requires a policy text head and supported position hold")
        super().start_autosteer(goal, interval_s)

    def pump_query(self, obs_processed: dict | None = None) -> bool:
        """Request a hold as soon as the control-thread autosteer sequencer queues text."""
        served = super().pump_query(obs_processed)
        if self.has_pending_query and self._policy_active.is_set() and not self.failed:
            self._request_language_hold()
        return served

    @property
    def control_thread_owns_policy(self) -> bool:
        """The RTC background thread owns the policy; it services queries in ``_rtc_loop``."""
        return False

    def _generate_text(self, obs_processed: dict, query: PolicyQuery) -> str:
        """Run the policy's text head.  Called on the RTC thread (see ``_rtc_loop``)."""
        obs_batch = build_dataset_frame(self._obs_features, obs_processed, prefix="observation")
        # Live task, read without consuming the task-changed edge: that belongs to the
        # chunk path.
        task = self.task
        obs_batch = prepare_observation_for_inference(
            obs_batch, torch.device(self._device), task, self._robot.robot_type
        )
        obs_batch = self._mark_query(obs_batch, query)
        generation = self._active_query_generation
        if generation != self._runtime.generation:
            raise RuntimeError("Language result belongs to an invalidated execution generation")
        preprocessed = self._language_preprocessor(obs_batch)
        with torch.inference_mode():
            # No str() coercion: _service_query validates the return value.
            result = self._policy.generate_text(preprocessed)
        if self.failed or generation != self._runtime.generation:
            raise RuntimeError("Language result belongs to an invalidated execution generation")
        if isinstance(result, str) and len(result) > DEFAULT_MAX_TEXT_OUTPUT_CHARS:
            raise ValueError("Language result exceeds the configured output bound")
        return result

    def _query_context_valid(self, query: PolicyQuery) -> bool:
        return (
            not self.failed
            and self._policy_active.is_set()
            and self._active_query_generation == self._runtime.generation
            and query.task_version == self.task_version
            and (
                query.kind is not QueryKind.NEXT_SUBTASK
                or query.intent_generation == self.query_intent_generation
            )
        )

    # ------------------------------------------------------------------
    # RTC: background inference thread
    # ------------------------------------------------------------------

    def _rtc_loop(self) -> None:
        """Own all policy/processor mutations and use the shared chunk runtime."""
        try:
            # Exercise both continuation branches and a nonzero delay before motion.
            # These representative graphs cannot cover every task/shape specialization.
            warmup_required = self._compile_warmup_inferences if self._use_torch_compile else 0
            inference_count = 0
            warmup_previous: tuple[torch.Tensor, torch.Tensor] | None = None
            consecutive_discards = 0
            while not self._shutdown_event.is_set() and not self.failed:
                for event in self._runtime.drain_wait_events():
                    if event["event"] == "waiting":
                        logger.warning(
                            "RTC actions exhausted; retaining last target for up to %.3fs", event["grace_s"]
                        )
                    else:
                        logger.info("RTC fresh actions ready after %.3fs waiting", event["wait_s"])
                # Reset is ordered behind any model call already executing. The
                # control thread has already revoked its old generation locally.
                with self._obs_lock:
                    reset_pending, tuning = self._reset_pending, self._pending_rtc_tuning
                    self._reset_pending, self._pending_rtc_tuning = False, None
                if tuning:
                    with self._runtime.lock:
                        for name, value in tuning.items():
                            setattr(self._rtc_config, name, value)
                if reset_pending:
                    warmup_previous = None
                    self._policy.reset()
                    self._preprocessor.reset()
                    self._postprocessor.reset()
                    self._language_preprocessor.reset()
                with self._obs_lock:
                    preparation = self._compile_preparation
                if preparation is not None:
                    self._prepare_compile_snapshot(preparation)
                    if self.ready:
                        inference_count = warmup_required
                    continue
                if not self._policy_active.is_set():
                    time.sleep(_RTC_IDLE_SLEEP_S)
                    continue
                if self.has_pending_query:
                    self._request_language_hold()
                if self._hold.requested:
                    if not self._hold.acknowledged:
                        time.sleep(_RTC_IDLE_SLEEP_S)
                        continue
                    with self._obs_lock:
                        obs = self._obs_holder.get("obs")
                        generation = self._runtime.generation
                        self._active_query_generation = generation
                        self._runtime.complete_starvation_invalidation(generation)
                        starvation = self._hold.reason == "Action starvation"
                    if starvation:
                        self._policy.drop_queued_actions()
                        with self._obs_lock:
                            if self._hold.reason == "Action starvation" and self._runtime.release_hold(
                                generation
                            ):
                                self._hold.clear()
                                self._obs_holder["obs"] = None
                        continue
                    if obs is None:
                        time.sleep(_RTC_IDLE_SLEEP_S)
                        continue
                    self._policy.drop_queued_actions()
                    self._service_query(obs)
                    with self._obs_lock:
                        # Pause/reset/fault during text never grants permission to
                        # resume. A healthy active run must obtain fresh actions.
                        if self._runtime.release_hold(generation):
                            self._hold.clear()
                            self._obs_holder["obs"] = None
                    continue
                if self._rtc_queue_threshold < 0 or not self._runtime.should_request():
                    time.sleep(_RTC_IDLE_SLEEP_S)
                    continue
                with self._obs_lock:
                    obs = self._obs_holder.get("obs")
                    capture_time = self._obs_holder.get("capture_time")
                    epoch_before = self._reset_epoch
                if obs is None or capture_time is None:
                    time.sleep(_RTC_IDLE_SLEEP_S)
                    continue
                with self._task_lock:
                    task, task_version = self._task, self._task_version
                    self._task_changed = False
                frame = build_dataset_frame(self._obs_features, obs, prefix="observation")
                observation = ObservationSnapshot(frame, capture_time, task, task_version)
                with self._obs_lock:
                    if epoch_before != self._reset_epoch or self._reset_pending:
                        continue
                    request = self._runtime.begin(observation)
                if request is None:
                    time.sleep(_RTC_IDLE_SLEEP_S)
                    continue
                previous = request.continuation.model_actions
                canonical_previous = request.continuation.canonical_actions
                delay = request.delay
                if inference_count < warmup_required and warmup_previous is not None:
                    previous, canonical_previous = warmup_previous
                    delay = 0 if inference_count == 1 else 1
                    if self._runtime.mode is ExecutionMode.RTC_TRAINED and delay:
                        delay = min(self._policy_spec.training_max_delay, self._rtc_config.execution_horizon)
                prediction = self._predict_observation(
                    observation.features, task, request.mode, previous, canonical_previous, delay
                )
                original, processed = prediction.model_actions, prediction.canonical_actions
                if inference_count < warmup_required:
                    # Warmup cannot leave motion or processor state for rollout.
                    with self._runtime.lock:
                        if self._runtime.pending is not request or self._runtime.failure:
                            continue
                        self._runtime.pending = None
                    inference_count += 1
                    horizon = self._rtc_config.execution_horizon
                    warmup_previous = (original[-horizon:], processed[-horizon:])
                    if inference_count == warmup_required:
                        self._policy.reset()
                        self._preprocessor.reset()
                        self._postprocessor.reset()
                        with self._runtime.lock:
                            self._runtime.action_timeout = self._action_timeout_s
                        warmup_previous = None
                        self._compile_warmup_done.set()
                    continue
                chunk = ActionChunk(
                    model_actions=original,
                    canonical_actions=processed,
                    execution_steps=len(processed),
                    provenance=ActionProvenance(capture_time, task, task_version),
                )
                with self._task_lock:
                    accepted = self._runtime.accept(request, chunk, task_version=self._task_version)
                if accepted:
                    consecutive_discards = 0
                elif request.generation != self._runtime.generation:
                    logger.info("Discarding action chunk computed before an engine reset or hold")
                elif (
                    self._rtc_config.mode == "trained"
                    and request.observation.task_version == self.task_version
                ):
                    consecutive_discards += 1
                    if consecutive_discards >= _RTC_MAX_CONSECUTIVE_DISCARDS:
                        raise _TrainedRTCDelayExceededError(
                            "Trained RTC inference repeatedly exceeded the conditioned/checkpoint overlap; "
                            "increase playback coverage, reduce action FPS, or use guided RTC."
                        )
        except Exception as exc:
            self._failure_traceback = traceback.format_exc()
            logger.exception("Fatal error in RTC thread: %s", exc)
            self._runtime.fault(str(exc))
            self._rtc_error.set()
            self._compile_warmup_done.set()
