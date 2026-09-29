# -*- coding: utf-8 -*-
"""On-Policy Distillation (OPD) workflow for AlfWorld -- FULL-MEMORY variant.

Deliberate sibling of OPD_workflow.py, NOT a replacement for it. That file's
own docstring documents why it was fixed to rebuild `messages` fresh every
turn (a single self-contained turn, capped HISTORY_LENGTH=2 textual summary
only): a prior full-memory training run showed prompt_length/clip_ratio of
0.52-0.67 at max_prompt_tokens=10240, silently truncating over half of all
training prompts and producing a checkpoint that never learned to close an
<action> tag (0/720 turns).

This file exists to re-test full-memory training WITHOUT raising any length
limits (max_prompt_tokens/max_response_tokens/max_token_len_per_gpu all left
exactly as opd.yaml already has them), per an explicit request to instead
test whether the plain (non-Instruct) Qwen3-30B-A3B teacher -- known from
this session's zero-shot evals to behave very differently from the
-Instruct-2507 revision (less prone to rambling/verbose responses) -- avoids
the original failure mode by keeping the student's own turn responses (and
therefore the growing conversation) naturally shorter, without needing a
bigger context budget. This is an open empirical question, not a resolved
one: if prompt truncation reappears at this same rate, that would indicate
the original failure was intrinsic to full-memory accumulation over long
episodes regardless of teacher identity, not specific to the -Instruct-2507
teacher's verbosity. Watch prompt_length/clip_ratio during training to see
which hypothesis holds.

Only real change from OPD_workflow.py: `_run_episode` accumulates a growing
`self._memory` list of every turn's (user, assistant) messages instead of
rebuilding a fresh single-turn `messages` list each round -- mirrors the
eval-side split between run_episode_tcod.py (single self-contained turn) and
run_episode.py (growing memory) in alfworld_ts_probe/. Each turn's
`user_content` still embeds the same capped HISTORY_LENGTH=2 textual summary
via ALFWORLD_TEMPLATE -- that part is unchanged; the only difference is
whether the RAW conversation (not just the textual summary) also
accumulates across turns.
"""

from dataclasses import asdict
from typing import Dict, List, Optional

from trinity.common.experience import Experience
from trinity.common.models.model import ModelWrapper
from trinity.common.workflows import WORKFLOWS, Task, Workflow

from trinity.common.workflows.envs.TCOD.alfworld.utils import (
    ALFWORLD_TEMPLATE_NO_HIS,
    ALFWORLD_TEMPLATE,
    HISTORY_LENGTH,
    parse_action,
    format_observation,
    _extract_task,
    _format_history,
    _create_alfworld_env,
)


@WORKFLOWS.register_module("OPD_alfworld_workflow_fullmemory")
class OnPolicyDistillVerlAgentAlfworldWorkflowFullMemory(Workflow):
    """On-policy distillation workflow for AlfWorld, full-memory variant.

    Identical to OnPolicyDistillVerlAgentAlfworldWorkflow (OPD_workflow.py)
    except the student sees the whole accumulated conversation each turn,
    not a single self-contained turn. See module docstring above.
    """

    is_async: bool = True
    can_reset: bool = True
    can_repeat: bool = False

    def __init__(
        self,
        *,
        task: Task,
        model: ModelWrapper,
        auxiliary_models: Optional[List[ModelWrapper]] = None,
    ):
        super().__init__(
            task=task,
            model=model,
            auxiliary_models=auxiliary_models,
        )
        self.reset(task)

        assert (
            self.auxiliary_model_wrappers is not None
            and len(self.auxiliary_model_wrappers) >= 1
        ), "On-policy distillation requires at least one auxiliary model as teacher."
        self.teacher_model = self.auxiliary_model_wrappers[0]

        self.temperature = task.workflow_args.get("temperature", 1.0)
        self.max_env_steps = task.workflow_args.get("max_env_steps", 30)
        self.is_eval = task.is_eval

    def reset(self, task: Task):
        """Reset the workflow with a new task.

        Unlike BaseSimpleWorkflow, this does NOT require reward_fn.
        """
        self.task = task
        self.format_args = task.format_args
        self.raw_task = task.raw_task
        self.task_desc = task.task_desc or "0"
        self.is_eval = task.is_eval

    def set_repeat_times(self, repeat_times, run_id_base):
        self.repeat_times = repeat_times
        self.task.rollout_args.n = repeat_times
        self.run_id_base = run_id_base

    def compute_reward(self, response: Experience) -> float:
        """Return episode-level reward (same for all turns in the trajectory).

        Set in _run_episode: env reward when done, 0.0 when max steps exhausted.
        """
        return getattr(self, "_final_reward", 0.0)

    @property
    def rollout_args(self):
        return asdict(self.task.rollout_args)

    async def run_async(self) -> List[Experience]:
        game_file_path = self.task_desc
        env = _create_alfworld_env(game_file_path)
        try:
            return await self._run_episode(env)
        finally:
            env.close()

    async def _run_episode(self, env) -> List[Experience]:
        observation, info = env.reset()
        self._env_done = False
        self._env_rounds = 0

        task_description = _extract_task(observation)
        history: List[str] = []
        turn_responses: List[Experience] = []

        # Growing conversation across turns -- the one change from
        # OPD_workflow.py. See module docstring.
        memory: List[Dict[str, str]] = []

        kwargs = {**self.rollout_args, "n": 1}
        if kwargs.get("logprobs") is None:
            kwargs["logprobs"] = 0

        for r in range(self.max_env_steps):
            format_obs = format_observation(observation)
            admissible_commands = info.get("admissible_commands", [])
            if admissible_commands and isinstance(admissible_commands[0], list):
                admissible_commands = admissible_commands[0]
            reformatted_admissible = "\n ".join(
                f"'{s}'" for s in admissible_commands if s != "help"
            )

            if len(history) < HISTORY_LENGTH:
                user_content = ALFWORLD_TEMPLATE_NO_HIS.format(
                    current_observation=format_obs,
                    admissible_actions=reformatted_admissible,
                )
            else:
                action_history_str = "\n".join(
                    history[-HISTORY_LENGTH:]
                    if len(history) >= HISTORY_LENGTH
                    else history
                )
                user_content = ALFWORLD_TEMPLATE.format(
                    task_description=task_description,
                    step_count=r,
                    history_length=min(HISTORY_LENGTH, len(history)),
                    action_history=action_history_str,
                    current_step=r + 1,
                    current_observation=format_obs,
                    admissible_actions=reformatted_admissible,
                )

            # Growing conversation: append this turn's user message onto the
            # full history of every prior turn's (user, assistant) pair,
            # instead of a fresh single-turn `messages` list.
            memory = memory + [{"role": "user", "content": user_content}]

            # Step 1: Student samples this turn (same pattern as OnPolicyDistillWorkflow)
            responses = await self.model.chat_async(memory, **kwargs)
            response = responses[0]
            response_text = response.response_text or ""
            memory = memory + [{"role": "assistant", "content": response_text}]

            if response.logprobs is None:
                raise RuntimeError(
                    "OnPolicyDistillAlfworldWorkflowFullMemory requires student model to "
                    "return logprobs. Set rollout_args.logprobs (e.g. 0) in task config."
                )
            turn_responses.append(response)

            action = parse_action(response_text)
            history.append(_format_history(format_obs, r + 1, action))
            observation, reward, done, info = env.step(action)
            if done:
                self._env_done = True
                self._env_rounds = r + 1
                self._final_reward = 1.0
                break
        else:
            self._env_rounds = self.max_env_steps
            self._final_reward = 0.0  # failure: exhausted max steps

        # Step 2 & 3: Teacher logprobs and fill experience (mirror OnPolicyDistillWorkflow.run_async)
        # response.tokens is the full sequence for this turn: [prefix | response], where
        # prefix is now the FULL accumulated conversation up to and including
        # this turn's user message (not a single self-contained turn as in
        # OPD_workflow.py) -- same input the student had.
        per_turn_kl_sums: List[float] = []
        for i, response in enumerate(turn_responses):
            teacher_logprobs = await self.teacher_model.logprobs_async(
                tokens=response.tokens.tolist(),  # full input = prefix + student's response
                temperature=self.temperature,
            )

            resp_start = response.prompt_length - 1
            teacher_resp_logprobs = teacher_logprobs[resp_start:]
            student_resp_logprobs = response.logprobs

            assert len(teacher_resp_logprobs) == len(student_resp_logprobs), (
                f"Length mismatch: teacher_logprobs={len(teacher_resp_logprobs)}, "
                f"student_logprobs={len(student_resp_logprobs)}. "
                f"tokens={len(response.tokens)}, prompt_length={response.prompt_length}"
            )

            response.teacher_logprobs = teacher_resp_logprobs

            if response.metrics is None:
                response.metrics = {}
            response.reward = self.compute_reward(response)
            response.eid.run = getattr(self, "run_id_base", 0)
            response.eid.step = i

            kl_sum = (student_resp_logprobs - teacher_resp_logprobs).sum().item()
            per_turn_kl_sums.append(kl_sum)

        # Trajectory-level metrics (computed once for the whole trajectory)
        trajectory_kl_divergence = sum(per_turn_kl_sums)
        if turn_responses:
            last_response = turn_responses[-1]
            if last_response.metrics is None:
                last_response.metrics = {}
            last_response.metrics["env_rounds"] = self._env_rounds
            last_response.metrics["env_done"] = 1.0 if self._env_done else 0.0
            last_response.metrics["kl_divergence"] = trajectory_kl_divergence

        return turn_responses
