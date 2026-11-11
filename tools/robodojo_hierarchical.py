# Copyright 2026 Limx Dynamics
"""FluxThemis plugin: simulator facts + episode-local remote VLA planning.

Import this module through themis.custom_imports, in the RoboDojo interpreter.
No FluxVLA/model imports are allowed here: Isaac uses a different runtime.
"""

import copy
import json
import os
import socket
import subprocess
from itertools import combinations
from multiprocessing.connection import Connection
from pathlib import Path

from fluxthemis.engines.utils import ENVIRONMENTS, POLICY_CLIENTS
from fluxthemis.environments.sim.robodojo import RoboDojoEnvironment
from fluxthemis.model_clients.fluxvla_policy import FluxVLAPolicyClient
from fluxthemis.structures import ActionChunk


class PlannerProcess:
    """One private planner process per simulator policy client.

    GPU visibility is inherited: FluxVLA's eager model imports currently
    inspect CUDA even when this process only uses an API-backed planner.
    No VLA weights are loaded here.
    """

    def __init__(self, python, policy, timeout_s=180.0):
        self.timeout_s = timeout_s
        self.process = None
        self.connection = None
        root = Path(__file__).resolve().parents[1]
        parent, child = socket.socketpair()
        self.connection = Connection(parent.detach())
        env = dict(os.environ)
        env['PYTHONPATH'] = os.pathsep.join(
            filter(None, [str(root), env.get('PYTHONPATH')]))
        try:
            self.process = subprocess.Popen([
                python,
                str(root / 'scripts/planner_worker.py'), '--fd',
                str(child.fileno())
            ],
                                            pass_fds=(child.fileno(), ),
                                            env=env,
                                            cwd=root)
            child.close()
            self.request(command='configure', policy=policy)
        except BaseException:
            self.close()
            raise
        finally:
            child.close()

    def request(self, **request):
        if self.process is None or self.process.poll() is not None:
            raise RuntimeError('Planner process is not running')
        self.connection.send(request)
        if not self.connection.poll(self.timeout_s):
            self.close()
            raise TimeoutError('Planner process exceeded its time budget')
        response = self.connection.recv()
        if not response['ok']:
            raise RuntimeError('Planner process error: ' + response['error'])
        return response['result']

    def close(self):
        if self.connection is not None:
            self.connection.close()
            self.connection = None
        if self.process is not None:
            if self.process.poll() is None:
                self.process.terminate()
            try:
                self.process.wait(timeout=5)
            except subprocess.TimeoutExpired:
                self.process.kill()
                self.process.wait()
            self.process = None


@POLICY_CLIENTS.register_module()
class HierarchicalFluxVLAPolicyClient(FluxVLAPolicyClient):
    """Select the subtask BEFORE the server tokenizes the VLA prompt.

    Actual environment step counters acknowledge the previous action chunk.
    Predictions alone never consume a subtask's execution budget. Failed or
    blocked planning raises before any action request (no dummy robot action).
    FluxThemis owns final success and the environment-step episode limit.
    """

    def __init__(self,
                 transport,
                 policy,
                 planner_python,
                 planner_timeout_s=180.0):
        super().__init__(transport)
        self.policy_config = copy.deepcopy(policy)
        self.planner_python = planner_python
        self.planner_timeout_s = planner_timeout_s
        self.planner_process = None
        self._goal = None
        self._last_step = None
        self._pending_length = 0

    def setup(self):
        if self.planner_process is not None:
            return
        super().setup()
        try:
            self.planner_process = PlannerProcess(self.planner_python,
                                                  self.policy_config,
                                                  self.planner_timeout_s)
        except BaseException:
            self.close()
            raise

    def reset(self, task, episode_index, policy_seed):
        super().reset(task, episode_index, policy_seed)
        # RoboDojo's actual instruction becomes available on the first obs,
        # not in the inventory TaskSpec used by reset().
        self._goal = None
        self._last_step = None
        self._pending_length = 0

    def predict_action(self, observation, context):
        self._ensure_ready()
        if self.planner_process is None:
            raise RuntimeError('setup() must start the planner process')
        if context.get('episode_id') != self._episode_id:
            raise ValueError('Planner episode id does not match the client')
        goal = self._resolve_prompt(context)
        step = context['info'].get('step', 0)
        if type(step) is not int or step < 0:
            raise ValueError('Environment step counter must be nonnegative')
        executed = False
        if self._goal is None:
            self.planner_process.request(command='reset', goal=goal)
            self._goal = goal
        else:
            if goal != self._goal:
                raise ValueError('Episode goal changed without reset()')
            delta = step - self._last_step
            if not 0 < delta <= self._pending_length:
                raise ValueError(
                    'Missing or invalid execution acknowledgement')
            executed = True
        event = self.planner_process.request(
            command='step',
            observation=dict(observation),
            observation_id=step,
            executed_previous_chunk=executed)
        print('[planner] ' + json.dumps(event), flush=True)
        if event['status'] != 'ready':
            raise RuntimeError('Planner stopped without issuing actions: ' +
                               json.dumps(event))
        vla_context = dict(context, task_description=event['instruction'])
        # The original goal/observation is not mutated. The selected subtask
        # travels through the normal stateless VLA request/denormalization.
        chunk = super().predict_action(observation, vla_context)
        self._last_step = step
        self._pending_length = len(chunk.actions)
        return ActionChunk(
            actions=chunk.actions,
            metadata=dict(
                chunk.metadata,
                planning=event,
                goal=self._goal,
                environment_step=step,
                predicates=copy.deepcopy(observation.get('predicates', {}))))

    def close(self):
        try:
            if self.planner_process is not None:
                self.planner_process.close()
                self.planner_process = None
        finally:
            super().close()


@ENVIRONMENTS.register_module()
class RoboDojoStackBlocksEnvironment(RoboDojoEnvironment):
    """Read-only task predicates, using RoboDojo's own reward thresholds.

    No dataset labels, trajectory annotations or scripted actions are used.
    This adapter is deliberately task-specific, not an all-task oracle.
    """

    def __init__(self, task_name='stack_blocks', **kwargs):
        if task_name != 'stack_blocks':
            raise ValueError(
                'This predicate adapter supports stack_blocks only')
        super().__init__(task_name=task_name, **kwargs)

    def _with_predicates(self, observation):
        rm = self._env.reward_manager
        threshold = self._env._stacked_xy_thresholds()

        def stacked(labels):
            check = rm.is_stacked(list(labels), xy_threshold=threshold)
            return bool(rm.check_once(check, 0))

        labels = ['block_0', 'block_1', 'block_2']
        released = bool(rm.check_once(rm.is_all_gripper_open(0.8), 0))
        return dict(
            observation,
            predicates={
                'two_stacked':
                released
                and any(stacked(pair) for pair in combinations(labels, 2)),
                'three_stacked':
                released and stacked(labels),
                # Only the environment may certify episode success.
                'environment_success':
                bool(self._env.success[0]),
            })

    def reset(self, *args, **kwargs):
        observation, info = super().reset(*args, **kwargs)
        return self._with_predicates(observation), info

    def step(self, action):
        from dataclasses import replace
        result = super().step(action)
        return replace(
            result, observation=self._with_predicates(result.observation))
