from __future__ import annotations

from dataclasses import dataclass
from typing import Dict, List, Optional, Tuple

from ha_lmapf.core.grid import manhattan, neighbors
from ha_lmapf.core.interfaces import SimStateView
from ha_lmapf.core.types import Observation, StepAction
from ha_lmapf.local_tier.conflict_resolution.base import BaseConflictResolver, detect_imminent_conflict

Cell = Tuple[int, int]


@dataclass
class _TokenState:
    owner: int
    win_streak: int = 0
    last_step: int = -1


class TokenPassingResolver(BaseConflictResolver):
    """
    Communication-based style resolver approximated via token ownership per contested cell.
    Deterministic given sim state.

    Priority tuple (higher is better):
      urgency = -distance_to_goal (smaller distance => larger priority)
      wait_steps (larger wait => higher priority)
      -agent_id (smaller id => higher priority)

    Fairness:
      if the same owner wins on the same cell for K consecutive conflicts, rotate ownership
      to the next best contender (if any).
    """

    def __init__(self, fairness_k: int = 5) -> None:
        self.tokens: Dict[Cell, _TokenState] = {}
        self.fairness_k = int(max(1, fairness_k))

    def resolve(
            self,
            agent_id: int,
            desired_cell: Cell,
            sim_state: SimStateView,
            observation: Observation,
            rng=None,  # unused
    ) -> StepAction:
        conflict = detect_imminent_conflict(agent_id, desired_cell, sim_state)
        if conflict is None:
            # No imminent agent-agent conflict, proceed by mapping desired move to action
            return self.action_toward(sim_state.agents[agent_id].pos, desired_cell)

        # Token is associated with the contested desired cell (vertex conflict) or the "to" cell (edge conflict)
        key_cell = desired_cell if conflict.kind == "vertex" else desired_cell

        contenders = self._contenders_for_cell(key_cell, sim_state)
        if agent_id not in contenders:
            contenders.append(agent_id)
        contenders = sorted(set(contenders))

        # Choose winner by priority tuple
        winner = max(contenders, key=lambda aid: self._priority(aid, sim_state))

        # Fairness rotation
        tok = self.tokens.get(key_cell)
        current_step = sim_state.step
        if tok is None:
            tok = _TokenState(owner=winner, win_streak=1, last_step=current_step)
            self.tokens[key_cell] = tok
        else:
            if tok.owner == winner:
                # Only increment streak once per timestep (resolve is called per-agent)
                if current_step != tok.last_step:
                    tok.win_streak += 1
                    tok.last_step = current_step
            else:
                tok.owner = winner
                tok.win_streak = 1
                tok.last_step = current_step

            if tok.win_streak >= self.fairness_k and len(contenders) > 1:
                # Rotate to next best contender (excluding current owner)
                ordered = sorted(contenders, key=lambda aid: self._priority(aid, sim_state), reverse=True)
                if ordered and ordered[0] == tok.owner:
                    rotated = ordered[1]
                    tok.owner = rotated
                    tok.win_streak = 1
                    winner = rotated

        if winner == agent_id:
            return self.action_toward(sim_state.agents[agent_id].pos, desired_cell)

        # Non-owner: yield or side-step safely
        side = self._safe_side_step(agent_id, sim_state, observation)
        if side is not None:
            return self.action_toward(sim_state.agents[agent_id].pos, side)
        return StepAction.WAIT

    def _priority(self, agent_id: int, sim_state: SimStateView) -> Tuple[int, int, int]:
        a = sim_state.agents[agent_id]
        # urgency: inverse distance -> use negative distance (higher is better)
        if a.goal is None:
            dist = 10 ** 9
        else:
            dist = manhattan(a.pos, a.goal)
        urgency = -dist
        return (urgency, int(a.wait_steps), -int(agent_id))

    def _contenders_for_cell(self, cell: Cell, sim_state: SimStateView) -> List[int]:
        """
        Conservative: consider agents that are adjacent to the contested cell or currently in it.
        """
        cont: List[int] = []
        for aid, a in sim_state.agents.items():
            if a.pos == cell or manhattan(a.pos, cell) == 1:
                cont.append(aid)
        return cont

    def _safe_side_step(
            self,
            agent_id: int,
            sim_state: SimStateView,
            observation: Observation,
    ) -> Optional[Cell]:
        """
        Pick a deterministic side-step (neighbor cell) that is free and does not create an imminent conflict.
        Preference order: UP, DOWN, LEFT, RIGHT (via neighbors()).
        """
        cur = sim_state.agents[agent_id].pos
        for nb in neighbors(cur):
            if not sim_state.env.is_free(nb):
                continue
            if nb in observation.blocked:
                continue
            c = detect_imminent_conflict(agent_id, nb, sim_state)
            if c is None:
                return nb
        return None
