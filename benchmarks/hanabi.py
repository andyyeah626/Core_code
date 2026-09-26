from __future__ import annotations

import json
from pathlib import Path
import random
from typing import Any, Callable, Protocol

from .protocol import DecisionFrame, Transition


class HanabiPartner(Protocol):
    def reset(self, seed: int) -> None: ...

    def act(
        self, observation: str, legal_actions: tuple[int, ...],
        action_labels: dict[int, str],
    ) -> int: ...


class RuleHanabiPartner:
    """Small deterministic partner used to validate the public interface."""

    def __init__(self, profile: str = "hint_first") -> None:
        if profile not in {"hint_first", "discard_first", "play_first"}:
            raise ValueError(f"Unknown rule partner {profile!r}")
        self.profile = profile
        self._rng = random.Random(0)

    def reset(self, seed: int) -> None:
        self._rng.seed(seed)

    def act(self, observation: str, legal_actions: tuple[int, ...],
            action_labels: dict[int, str]) -> int:
        priorities = {
            "hint_first": ("Reveal", "Discard", "Play"),
            "discard_first": ("Discard", "Reveal", "Play"),
            "play_first": ("Play", "Reveal", "Discard"),
        }[self.profile]
        for prefix in priorities:
            candidates = [a for a in legal_actions if prefix in action_labels[a]]
            if candidates:
                return candidates[self._rng.randrange(len(candidates))]
        if not legal_actions:
            raise ValueError("Partner was asked to act without legal actions")
        return legal_actions[0]


class AdaptiveHanabiCheckpointPartner:
    """Stable bridge for Adaptive-Hanabi/OBL checkpoint policies.

    The repository's native CUDA actors do not share OpenSpiel's Python bot
    interface, so loading is explicit. ``loader`` must return an object exposing
    reset(seed) and act(observation, legal_actions, action_labels).
    """

    def __init__(self, checkpoint: str | Path,
                 loader: Callable[[Path], HanabiPartner]) -> None:
        self.checkpoint = Path(checkpoint)
        self.loader = loader
        self._policy: HanabiPartner | None = None

    def reset(self, seed: int) -> None:
        if not self.checkpoint.is_file():
            raise FileNotFoundError(self.checkpoint)
        if self._policy is None:
            self._policy = self.loader(self.checkpoint)
        self._policy.reset(seed)

    def act(self, observation: str, legal_actions: tuple[int, ...],
            action_labels: dict[int, str]) -> int:
        if self._policy is None:
            raise RuntimeError("Call reset before checkpoint partner act")
        return int(self._policy.act(observation, legal_actions, action_labels))


class HanabiAdapter:
    game_id = "adaptive_hanabi"

    def __init__(self, partner: HanabiPartner, *, players: int = 2) -> None:
        if players != 2:
            raise ValueError("The first adapter revision supports two-player Hanabi")
        self.partner = partner
        self.players = players
        self._rng = random.Random(0)
        self._state = None
        self._seat = 0
        self._total = 0.0
        self._history: list[dict[str, Any]] = []

    def _resolve_chance(self) -> None:
        import pyspiel

        while self._state is not None and self._state.current_player() == pyspiel.PlayerId.CHANCE:
            outcomes = self._state.chance_outcomes()
            threshold = self._rng.random()
            running = 0.0
            selected = outcomes[-1][0]
            for action, probability in outcomes:
                running += probability
                if threshold <= running:
                    selected = action
                    break
            self._state.apply_action(selected)

    def reset(self, *, opponent_id: str, seed: int, seat: int = 0,
              training: bool = False) -> DecisionFrame:
        import pyspiel

        if seat not in (0, 1):
            raise ValueError("seat must be 0 or 1")
        self._rng.seed(seed)
        self.partner.reset(seed ^ 0xA11CE)
        self._seat = seat
        self._total = 0.0
        self._history = []
        game = pyspiel.load_game("hanabi", {"players": 2, "hand_size": 5})
        self._state = game.new_initial_state()
        self._resolve_chance()
        while not self._state.is_terminal() and self._state.current_player() != self._seat:
            self._play_partner()
        return self._frame(training=training)

    def _labels(self) -> dict[int, str]:
        return {int(a): self._state.action_to_string(int(a))
                for a in self._state.legal_actions()}

    def _observation(self) -> str:
        raw = self._state.observation_string(self._seat)
        return json.dumps({
            "game": "Two-player Hanabi",
            "player_visible_state": raw,
            "completed_public_actions": self._history,
            "objective": "Maximize the shared fireworks score while respecting private hands.",
            "legal_action_labels": {str(k): v for k, v in self._labels().items()},
        }, ensure_ascii=False, separators=(",", ":"))

    def _frame(self, *, training: bool = False) -> DecisionFrame:
        terminal = bool(self._state.is_terminal())
        return DecisionFrame(
            observation=(json.dumps({"game": "Two-player Hanabi", "terminal": True,
                                     "completed_public_actions": self._history},
                                    ensure_ascii=False, separators=(",", ":"))
                         if terminal else self._observation()),
            legal_actions=(() if terminal else tuple(str(a) for a in self._state.legal_actions())),
            cumulative_return=self._total,
            terminal=terminal,
        )

    def _play_partner(self) -> str:
        observation = self._state.observation_string(1 - self._seat)
        legal = tuple(int(a) for a in self._state.legal_actions())
        labels = self._labels()
        if hasattr(self.partner, "act_with_history"):
            action = int(self.partner.act_with_history(
                observation, legal, labels, tuple(dict(row) for row in self._history)))
        else:
            action = int(self.partner.act(observation, legal, labels))
        if action not in legal:
            raise ValueError(f"Partner returned illegal Hanabi action {action}")
        label = labels[action]
        self._state.apply_action(action)
        self._history.append({"actor": "partner", "action": label})
        self._resolve_chance()
        return label

    def step(self, action: str) -> Transition:
        if self._state is None:
            raise RuntimeError("Call reset first")
        if self._state.is_terminal() or self._state.current_player() != self._seat:
            raise RuntimeError("It is not the focal player's decision")
        legal = tuple(int(a) for a in self._state.legal_actions())
        try:
            action_id = int(action)
        except ValueError as error:
            raise ValueError(f"Hanabi action must be an integer ID, got {action!r}") from error
        if action_id not in legal:
            raise ValueError(f"Illegal Hanabi action ID {action_id}")
        own_label = self._labels()[action_id]
        self._state.apply_action(action_id)
        self._history.append({"actor": "self", "action": own_label})
        self._resolve_chance()
        events = []
        while not self._state.is_terminal() and self._state.current_player() != self._seat:
            events.append(self._play_partner())
        reward = 0.0
        if self._state.is_terminal():
            terminal_total = float(self._state.returns()[self._seat])
            reward = terminal_total - self._total
            self._total = terminal_total
        frame = self._frame()
        opponent_event = (json.dumps(events, ensure_ascii=False) if events else
                          "Game ended. Own terminal payoff only.")
        return Transition(frame=frame, opponent_event=opponent_event,
                          reward_delta=reward, terminal=frame.terminal,
                          evaluator_metrics={"public_action_count": len(self._history)})

    def close(self) -> None:
        self._state = None

    def fingerprint(self) -> dict[str, Any]:
        import pyspiel

        return {
            "adapter": type(self).__name__,
            "protocol_id": "adaptive-hanabi-closedset-v1",
            "pyspiel_version": getattr(pyspiel, "__version__", "unknown"),
            "partner_backend": type(self.partner).__name__,
        }
