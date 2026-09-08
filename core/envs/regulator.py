from abc import abstractmethod
from typing import Any, Optional, SupportsFloat

import numpy as np
import ray
import torch
from gymnasium.core import ActType, ObsType

from core.annotations import override
from core.envs.base import BaseEnv
from core.mechanism.base import Mechanism, VectorMechanism
from core.optimizers.base import Optimizer
from core.world.context import (
    Context,
    MechanismContext,
    MechanismStatus,
)


class RegulatorEnv(BaseEnv):
    def __init__(
        self,
        *,
        optimizer: Optional[Optimizer] = None,
        train_iters: int = 5,
        seeds: Optional[list[int]] = None,
        eval_seeds: Optional[list[int]] = None,
        **kwargs,
    ):
        super().__init__(**kwargs)
        self.inner: Optimizer = optimizer
        self.train_iters: int = train_iters
        self.seeds: list[int] = seeds or []
        self.eval_seeds: Optional[list[int]] = eval_seeds or None

        self._validate()

    def _validate(self):
        if self.inner is None:
            return  # analytic override mode allowed

        if self.train_iters <= 0:
            raise ValueError("train_iters must be >= 1 when optimizer is provided")

    @override(BaseEnv)
    def _reset(self):
        if self.observation_space is None:
            return 0.0
        return np.zeros(self.observation_space.shape, dtype=np.float32)

    @override(BaseEnv)
    def _step(
        self, mechanisms: list[Mechanism]
    ) -> tuple[ObsType, SupportsFloat, bool, bool, dict[str, Any]]:
        if self.inner is None:
            raise NotImplementedError(
                f"{self.__class__.__name__} has no inner optimizer. "
                f"Override `_step()` for analytic reward computation."
            )

        if not isinstance(mechanisms, list) or not all(
            isinstance(t, Mechanism) for t in mechanisms
        ):
            raise TypeError(
                f"{self.__class__.__name__} expected list[Mechanism], got {type(mechanisms)}"
            )

        # Reset policy weights for fresh equilibrium search each ES iteration
        if hasattr(self.inner, "reset"):
            self.inner.reset()

        # TODO PARALLELIZE Vectorize environment across θ candidates and train one ppo policy over mehcanism candidates
        # TODO other techiniques can also speed this up
        # for theta in thetas:
        #     self._publish(MechanismContext(theta=theta))
        for idx, m in enumerate(mechanisms):
            for seed in self.seeds:
                self._publish(
                    MechanismContext(
                        index=idx,
                        seed=seed,
                        status=MechanismStatus.published,
                        env_id=None,
                        mechanism=m,
                        metrics=None,
                    )
                )

        # TODO : why eval gets repeated ?
        # Train policy for train_iters iterations
        for _ in range(self.train_iters):
            ctx_registry = ray.get(self.world.get_ctx_registry.remote())

            # TODO remove env step contexsts
            ray.get(self.world.flush_ctx.remote(ctx_registry.keys()))
            ray.get(self.world.flush.remote(status=MechanismStatus.eval))
            self.inner.run()

        # TODO check if eval mechanisms published. If parallel and sequential eval both turned on
        # will be a problem
        if self.eval_seeds:
            # TODO flush all remote mechanisms and env_step ctx.
            # TODO initializing the envs with the seeds from eval_seeds
            # TODO flush all remote mechanisms and env_step ctx.
            # TODO eval results accumulate in eval and maintain training data !
            self.inner.evaluate()

        # plot results
        self.inner.report_metrics()
        metrics = self.inner.logger.peek()

        # Aggregate rewards
        reward = self.aggregate_rewards(metrics)

        # flush consumed contexts
        ray.get(self.world.flush_ctx.remote(ctx_registry.keys()))
        ray.get(self.world.flush.remote(status=MechanismStatus.eval))

        # return reduced data to outer optimizer
        # TODO route this through world in future
        # TODO applying nested reducers or in sequence
        reduced = self.inner.reduce_metrics()

        return None, reward, False, False, {"metrics": reduced}

    # @abstractmethod
    # @override(BaseEnv)
    # def observation(self, observation: ObsType) -> ObsType:
    #     # read downstream results from optimizer and compute aggregate
    #     raise NotImplementedError

    @abstractmethod
    def aggregate_rewards(self, ctx: list[Context]) -> SupportsFloat:
        return NotImplementedError

    # @abstractmethod
    @override(BaseEnv)
    def action(self, action: ActType) -> list[Mechanism]:
        # analytic path
        if self.inner is None:
            return action

        # 1) Mechanism space path (preferred)
        if self.m_space is not None:
            if isinstance(action, (list, tuple)):
                action = np.asarray(action, dtype=np.float32)

            if isinstance(action, np.ndarray):
                if action.ndim == 1:
                    action = action[None, :]  # (d,) -> (1, d)

                # TODO parallelize
                return [self.m_space.decode(x) for x in action]

            if torch.is_tensor(action):
                return self.action(action.detach().cpu().numpy())

            raise TypeError(f"Unsupported action type: {type(action)}")

        # 2) No mechanism_space: still guarantee Mechanism objects
        if isinstance(action, (list, tuple)):
            action = np.asarray(action, dtype=np.float32)

        if isinstance(action, np.ndarray):
            if action.ndim == 1:
                action = action[None, :]
            return [VectorMechanism(v) for v in action]

        if torch.is_tensor(action):
            return self.action(action.detach().cpu().numpy())

        # If someone passed an already-built Mechanism, allow it
        # (e.g., analytic tests).
        if hasattr(action, "to_vector"):
            return [action]  # type: ignore

        raise TypeError(
            f"Unsupported action type with no mechanism_space: {type(action)}"
        )
