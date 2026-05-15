"""Integration tests for the calendar scheduling game protocol."""
from __future__ import annotations

import asyncio
import uuid

import pytest
from collections import deque

from a2a_engine import EventLog, GameTraceBase
from calendar_game.game import CalendarGame, CalendarGameConfig
from calendar_game.agents import Agent, BaseClient, CapturingClient, GameConfig, TurnResult, DecideResult
from calendar_game.calendar import Calendar, validate_batch, apply_batch
from calendar_game.clients import ScriptedClient
from calendar_game.scenario import generate_scenario
from calendar_game.solver import solve_greedy, solve_optimal


# ---------------------------------------------------------------------------
# Helpers
# ---------------------------------------------------------------------------

def run_dry(seed=42, num_meetings=1, **kwargs):
    config = CalendarGameConfig(seed=seed, num_meetings=num_meetings, **kwargs)
    game = CalendarGame(config, dry_run=True)
    return game.run()


def _event_as_dict(event):
    """Normalise GameEvent (Pydantic model) or plain dict to a plain dict."""
    if isinstance(event, dict):
        return event
    return {"type": event.type, "data": event.data}


def _normalize(events):
    return [_event_as_dict(e) for e in events]


def events_of_type(trace, event_type):
    return [e for e in _normalize(trace.events) if e["type"] == event_type]


# ---------------------------------------------------------------------------
# Custom clients for testing
# ---------------------------------------------------------------------------

class AlwaysDMClient(BaseClient):
    """Sends a fixed number of DMs to a target on every turn."""
    def __init__(self, target_id: int, num_dms: int = 3):
        self.target_id = target_id
        self.num_dms = num_dms
        self.agent_id = -1
        self.meeting = None

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        self.agent_id = agent_id

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting = meeting

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        tool_calls = []
        if self.meeting is not None:
            meeting_id = self.meeting["id"]
            for _ in range(self.num_dms):
                tool_calls.append({
                    "type": "dm",
                    "to": self.target_id,
                    "meeting_id": meeting_id,
                    "content": "hello",
                })
        return TurnResult(tool_calls=tool_calls, text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)


class OneShotDMClient(BaseClient):
    """Sends one DM, either on its first turn or after receiving a message."""
    def __init__(self, target_id: int, content: str, trigger: str = "first_turn"):
        self.target_id = target_id
        self.content = content
        self.trigger = trigger
        self.agent_id = -1
        self.meeting_id = 1
        self.sent = False

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        self.agent_id = agent_id

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        should_send = (
            self.trigger == "first_turn"
            or (self.trigger == "on_message" and bool(messages))
        )
        if self.sent or not should_send:
            return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)
        self.sent = True
        meeting_id = messages[0]["meeting_id"] if messages else self.meeting_id
        return TurnResult(
            tool_calls=[{
                "type": "dm",
                "to": self.target_id,
                "meeting_id": meeting_id,
                "content": self.content,
            }],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)


class OneShotGroupchatFixedSlotClient(BaseClient):
    """Optionally sends one groupchat message, records inboxes, then schedules a fixed slot."""
    def __init__(self, slot: int, content: str | None = None, channel: str = "all_groupchat"):
        self.slot = slot
        self.content = content
        self.channel = channel
        self.sent = False
        self.meeting_id = 1
        self.received_messages: list[dict] = []

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        self.agent_id = agent_id

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]
        self.sent = False

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        self.received_messages.extend(messages)
        if self.content is not None and not self.sent:
            self.sent = True
            return TurnResult(
                tool_calls=[{
                    "type": self.channel,
                    "meeting_id": self.meeting_id,
                    "content": self.content,
                }],
                text=None, thinking=None, usage=None, latency_ms=None, raw=None,
            )
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": meeting["id"], "slot": self.slot}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return self.decide({"id": self.meeting_id}, "")


class OneShotMixedChatFixedSlotClient(BaseClient):
    """Sends both groupchat and DM messages once, records inboxes, then schedules a fixed slot."""
    def __init__(self, slot: int, dm_target: int | None = None, groupchat_channel: str = "all_groupchat"):
        self.slot = slot
        self.dm_target = dm_target
        self.groupchat_channel = groupchat_channel
        self.sent = False
        self.meeting_id = 1
        self.received_messages: list[dict] = []

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        self.agent_id = agent_id

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]
        self.sent = False

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        self.received_messages.extend(messages)
        if self.sent:
            return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)
        self.sent = True
        tool_calls = [{
            "type": self.groupchat_channel,
            "meeting_id": self.meeting_id,
            "content": "Group proposal: slot 0 works for me.",
        }]
        if self.dm_target is not None:
            tool_calls.append({
                "type": "dm",
                "to": self.dm_target,
                "meeting_id": self.meeting_id,
                "content": "Private note: I can also do slot 0.",
            })
        return TurnResult(tool_calls=tool_calls, text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": meeting["id"], "slot": self.slot}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return self.decide({"id": self.meeting_id}, "")


class InvalidBatchClient(BaseClient):
    """Always returns an invalid batch (schedule for non-existent slot 999)."""
    def __init__(self, meeting_id: int = 1):
        self.meeting_id = meeting_id
        self.agent_id = -1

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        self.agent_id = agent_id

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": self.meeting_id, "slot": 999}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": self.meeting_id, "slot": 999}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )


class FixedSlotClient(BaseClient):
    """Always schedules the meeting at a fixed slot."""
    def __init__(self, slot: int):
        self.slot = slot
        self.meeting_id = 1

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": self.meeting_id, "slot": self.slot}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return self.decide({}, "")


class FixedBatchClient(BaseClient):
    """Submits the same decision batch for the current meeting."""
    def __init__(self, actions: list[dict]):
        self.actions = actions
        self.meeting_id = 1

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        actions = [
            {**action, "meeting_id": self.meeting_id}
            if action.get("type") == "schedule"
            else action
            for action in self.actions
        ]
        return DecideResult(tool_calls=actions, text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return self.decide({"id": self.meeting_id}, "")


class MalformedToolClient(BaseClient):
    """Returns malformed model-style tool calls before falling back to valid decisions."""
    def __init__(self, decide_calls: list[object] | None = None):
        self.meeting_id = 1
        self.decide_calls = decide_calls if decide_calls is not None else []

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self.meeting_id = meeting["id"]

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(
            tool_calls=[None, {"type": "dm"}, {"type": "noop"}],  # type: ignore[list-item]
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=self.decide_calls,  # type: ignore[arg-type]
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(
            tool_calls=[{"type": "schedule", "meeting_id": self.meeting_id, "slot": 0}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )


def _build_game_with_clients(clients: list[BaseClient], seed: int = 42, num_slots: int = 16,
                              num_meetings: int = 1, dm_cap: int = 100, decision_retries: int = 3,
                              max_turns_per_round: int = 20) -> CalendarGame:
    """Build a CalendarGame with dry_run=True then swap in custom clients."""
    config = CalendarGameConfig(
        seed=seed,
        num_agents=len(clients),
        num_slots=num_slots,
        num_meetings=num_meetings,
        dm_cap=dm_cap,
        decision_retries=decision_retries,
        max_turns_per_round=max_turns_per_round,
    )
    game = CalendarGame(config, dry_run=True)
    return game, config


def _run_with_clients(clients: list[BaseClient], seed: int = 42, num_slots: int = 16,
                      num_meetings: int = 1, dm_cap: int = 100, decision_retries: int = 3,
                      max_turns_per_round: int = 20):
    """Run a game but with custom clients injected after construction."""
    config = CalendarGameConfig(
        seed=seed,
        num_agents=len(clients),
        num_slots=num_slots,
        num_meetings=num_meetings,
        dm_cap=dm_cap,
        decision_retries=decision_retries,
        max_turns_per_round=max_turns_per_round,
    )
    game = CalendarGame(config, dry_run=True)

    # Patch the run to inject custom clients
    original_run_async = game._run_async

    async def patched_run_async():
        scenario = generate_scenario(
            config.seed, config.num_agents, config.num_slots,
            config.density, config.pref_level, config.num_meetings,
        )
        optimal = solve_optimal(scenario["calendars"], scenario["meetings"], config.num_slots)
        greedy = solve_greedy(scenario["calendars"], scenario["meetings"], config.num_slots)

        agents: list[Agent] = []
        for agent_id, client in enumerate(clients):
            agent = Agent(client)
            cal = Calendar(num_slots=config.num_slots)
            cal.slots = list(scenario["calendars"][agent_id])
            agent.calendar = cal
            agents.append(agent)

        all_agent_ids = list(range(config.num_agents))
        for agent_id, agent in enumerate(agents):
            gc = GameConfig(
                num_agents=config.num_agents,
                num_slots=config.num_slots,
                agent_id=agent_id,
                all_agent_ids=all_agent_ids,
                dm_cap=config.dm_cap,
                decision_retries=config.decision_retries,
            )
            agent.register(agent_id, gc)

        # Reuse game's event log and loop
        game.events = EventLog()
        game.events.append("game_start", data={
            "round": -1, "turn": -1, "phase": "GAME_START", "agent_id": None,
            "scenario_seed": config.seed, "num_agents": config.num_agents, "num_slots": config.num_slots,
            "optimal_cost": optimal.get("cost"), "greedy_cost": greedy.get("cost"),
        })

        displacement_cost = {i: 0 for i in range(config.num_agents)}
        total_client_calls = {i: 0 for i in range(config.num_agents)}
        round_outcomes = []

        for round_num, meeting in enumerate(scenario["meetings"]):
            game.events.append("round_start", data={
                "round": round_num, "turn": 0, "phase": "CHEAP_TALK", "agent_id": None,
                "meeting": meeting,
            })

            for agent_id in meeting["participants"]:
                agents[agent_id].start_round(meeting, round_num)

            already_queued: set[int] = set()
            turn_index = 0

            has_activity = True
            while has_activity and turn_index < config.max_turns_per_round:
                has_activity = False

                for agent_id in meeting["participants"]:
                    inbox_snapshot = list(agents[agent_id].inbox_queue)
                    game.events.append("turn_start", data={
                        "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                        "agent_id": agent_id, "inbox_drained": inbox_snapshot,
                        "calendar_render": agents[agent_id].calendar.render(),
                    })
                    result = agents[agent_id].turn(turn_index, config.max_turns_per_round)
                    total_client_calls[agent_id] += 1
                    game.events.append("turn_end", data={
                        "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                        "agent_id": agent_id, "tool_calls": result.tool_calls,
                        "text": result.text, "thinking": result.thinking,
                        "usage": result.usage.__dict__ if result.usage else None,
                        "latency_ms": result.latency_ms, "raw_api_response": result.raw,
                    })

                    for tool in result.tool_calls:
                        if tool.get("type") != "dm":
                            continue
                        to = int(tool["to"])
                        msg = {"from": agent_id, "meeting_id": tool.get("meeting_id", meeting["id"]),
                               "content": str(tool.get("content", ""))}
                        agents[to].inbox_queue.append(msg)
                        has_activity = True
                        game.events.append("dm_sent", data={
                            "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                            "agent_id": agent_id, "from_agent": agent_id, "to_agent": to,
                            "meeting_id": msg["meeting_id"], "content": msg["content"],
                        })
                        if to not in meeting["participants"] and to not in already_queued:
                            already_queued.add(to)

                queue = list(already_queued - set(meeting["participants"]))
                for agent_id in queue:
                    inbox_snapshot = list(agents[agent_id].inbox_queue)
                    game.events.append("turn_start", data={
                        "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                        "agent_id": agent_id, "inbox_drained": inbox_snapshot,
                        "calendar_render": agents[agent_id].calendar.render(),
                    })
                    result = agents[agent_id].turn(turn_index, config.max_turns_per_round)
                    total_client_calls[agent_id] += 1
                    game.events.append("turn_end", data={
                        "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                        "agent_id": agent_id, "tool_calls": result.tool_calls,
                        "text": result.text, "thinking": result.thinking,
                        "usage": result.usage.__dict__ if result.usage else None,
                        "latency_ms": result.latency_ms, "raw_api_response": result.raw,
                    })
                    for tool in result.tool_calls:
                        if tool.get("type") != "dm":
                            continue
                        to = int(tool["to"])
                        msg = {"from": agent_id, "meeting_id": tool.get("meeting_id", meeting["id"]),
                               "content": str(tool.get("content", ""))}
                        agents[to].inbox_queue.append(msg)
                        has_activity = True
                        game.events.append("dm_sent", data={
                            "round": round_num, "turn": turn_index, "phase": "CHEAP_TALK",
                            "agent_id": agent_id, "from_agent": agent_id, "to_agent": to,
                            "meeting_id": msg["meeting_id"], "content": msg["content"],
                        })
                        if to not in already_queued:
                            already_queued.add(to)

                turn_index += 1

            for agent_id in meeting["participants"]:
                snapshot_render = agents[agent_id].calendar.snapshot().render()
                game.events.append("decide_start", data={
                    "round": round_num, "turn": turn_index, "phase": "DECISION",
                    "agent_id": agent_id, "calendar_snapshot_render": snapshot_render,
                })
                result = agents[agent_id].decide(meeting)
                total_client_calls[agent_id] += 1
                game.events.append("decide_end", data={
                    "round": round_num, "turn": turn_index, "phase": "DECISION",
                    "agent_id": agent_id, "tool_calls": result.tool_calls,
                    "text": result.text, "thinking": result.thinking,
                    "usage": result.usage.__dict__ if result.usage else None,
                    "latency_ms": result.latency_ms, "raw_api_response": result.raw,
                    "retry_count": result.retry_count, "status": "pending",
                })

                actions = [
                    {**a, "cost": meeting.get("cost", 1)} if a.get("type") == "schedule" and a.get("meeting_id") == meeting["id"] else a
                    for a in result.tool_calls if a.get("type") in ("schedule", "reschedule")
                ]
                for attempt in range(config.decision_retries + 1):
                    ok, conflict = validate_batch(agents[agent_id].calendar, actions)
                    if ok:
                        for action in actions:
                            if action.get("type") == "reschedule":
                                from_slot = int(action["from_slot"])
                                item = agents[agent_id].calendar.get(from_slot)
                                if isinstance(item, dict) and "cost" in item:
                                    displacement_cost[agent_id] += int(item["cost"])
                        apply_batch(agents[agent_id].calendar, actions)
                        game.events.append("batch_applied", data={
                            "round": round_num, "turn": turn_index, "phase": "DECISION",
                            "agent_id": agent_id, "actions": actions,
                            "calendar_render_after": agents[agent_id].calendar.render(),
                        })
                        break
                    else:
                        game.events.append("batch_rejected", data={
                            "round": round_num, "turn": turn_index, "phase": "DECISION",
                            "agent_id": agent_id, "attempt": attempt,
                            "conflict_description": conflict, "actions": actions,
                        })
                        if attempt < config.decision_retries:
                            retry_result = agents[agent_id].client.retry_decide(
                                attempt + 1, config.decision_retries, conflict
                            )
                            total_client_calls[agent_id] += 1
                            actions = [
                                {**a, "cost": meeting.get("cost", 1)} if a.get("type") == "schedule" and a.get("meeting_id") == meeting["id"] else a
                                for a in retry_result.tool_calls if a.get("type") in ("schedule", "reschedule")
                            ]
                        else:
                            game.events.append("decision_failed", data={
                                "round": round_num, "turn": turn_index, "phase": "DECISION",
                                "agent_id": agent_id,
                                "attempts_exhausted": config.decision_retries + 1,
                            })
                            break

            per_agent_slot: dict[str, int | None] = {}
            for agent_id in meeting["participants"]:
                found_slot = None
                for slot_idx, slot_val in enumerate(agents[agent_id].calendar.slots):
                    if isinstance(slot_val, dict) and slot_val.get("meeting_id") == meeting["id"]:
                        found_slot = slot_idx
                        break
                per_agent_slot[str(agent_id)] = found_slot

            slots_chosen = [s for s in per_agent_slot.values() if s is not None]
            coordinated = len(slots_chosen) == len(meeting["participants"]) and len(set(slots_chosen)) == 1

            slot_conflicts: dict[str, list[int]] = {}
            for agent_id in range(config.num_agents):
                seen: dict[int, list] = {}
                for slot_idx, slot_val in enumerate(agents[agent_id].calendar.slots):
                    if isinstance(slot_val, dict) and "meeting_id" in slot_val:
                        seen.setdefault(slot_idx, []).append(f"M{slot_val['meeting_id']}")
                conflicts = [slot_idx for slot_idx, vals in seen.items() if len(vals) > 1]
                if conflicts:
                    slot_conflicts[str(agent_id)] = conflicts

            game.events.append("resolution", data={
                "round": round_num, "turn": turn_index, "phase": "RESOLUTION",
                "agent_id": None, "meeting_id": meeting["id"],
                "per_agent_slot": per_agent_slot, "coordinated": coordinated,
                "slot_conflicts": slot_conflicts,
            })
            round_outcomes.append({
                "meeting_id": meeting["id"], "coordinated": coordinated,
                "per_agent_slot": per_agent_slot, "slot_conflicts": slot_conflicts,
            })

        total_meetings = len(scenario["meetings"])
        coordinated_meetings = sum(1 for o in round_outcomes if o["coordinated"])
        coordination_rate = coordinated_meetings / total_meetings if total_meetings > 0 else 1.0
        agents_with_conflicts = sum(
            1 for agent_id in range(config.num_agents)
            if any(str(agent_id) in o["slot_conflicts"] for o in round_outcomes)
        )
        slot_conflict_rate = agents_with_conflicts / config.num_agents if config.num_agents > 0 else 0.0
        realized_cost = sum(displacement_cost.values())
        optimal_cost = optimal.get("cost") or 0
        efficiency = max(0.0, min(1.0, 1 - realized_cost / optimal_cost)) if optimal_cost > 0 else 1.0
        per_agent_cost_list = [displacement_cost[i] for i in range(config.num_agents)]
        max_cost = max(per_agent_cost_list) if per_agent_cost_list else 0
        fairness = min(per_agent_cost_list) / max_cost if max_cost > 0 else 1.0
        metrics = {
            "coordination_rate": coordination_rate, "slot_conflict_rate": slot_conflict_rate,
            "efficiency": efficiency, "fairness": fairness,
            "meetings_scheduled": coordinated_meetings, "realized_cost": realized_cost,
            "optimal_cost": optimal_cost,
        }
        game.events.append("game_end", data={
            "round": len(scenario["meetings"]), "turn": 0, "phase": "GAME_END", "agent_id": None,
            **metrics,
        })

        return GameTraceBase(
            game_id=str(uuid.uuid4()),
            config=config,
            events=game.events.all(),
            final_state={
                "calendars": [agent.calendar.slots for agent in agents],
                "per_agent_cost": per_agent_cost_list,
                "round_outcomes": round_outcomes,
            },
            metrics=metrics,
        ), agents

    return asyncio.run(patched_run_async())


# ---------------------------------------------------------------------------
# Tests
# ---------------------------------------------------------------------------

def test_malformed_tool_calls_are_rejected_not_crashing():
    config = CalendarGameConfig(
        seed=1,
        num_agents=2,
        num_slots=2,
        num_meetings=1,
        decision_retries=1,
        max_turns_per_round=2,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    scenario = {
        "seed": 1,
        "num_agents": 2,
        "num_slots": 2,
        "calendars": [[None, None], [None, None]],
        "meetings": [{"id": 1, "participants": [0, 1], "duration": 1, "cost": 1}],
        "optimal": {"cost": 0, "assignments": {"1": 0}},
        "greedy": {"cost": 0, "assignments": {"1": 0}},
        "feasible": True,
    }
    clients: list[BaseClient] = [
        MalformedToolClient(decide_calls=[None, {"type": "schedule"}]),
        FixedSlotClient(slot=0),
    ]
    agents: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(config.num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents.append(agent)

    trace = game._run_with_agents(agents, scenario)

    invalid = events_of_type(trace, "invalid_tool_call")
    assert invalid
    rejected = events_of_type(trace, "batch_rejected")
    assert any("missing required field" in e["data"]["conflict_description"] for e in rejected)
    assert trace.metrics["meetings_scheduled"] == 1


def test_asymmetric_agent_densities_generate_different_calendar_loads():
    scenario = generate_scenario(
        seed=11,
        num_agents=3,
        num_slots=10,
        density=0.5,
        pref_level=1,
        num_meetings=1,
        participant_lists=[[0, 1, 2]],
        speaker_orders=[[0, 1, 2]],
        agent_densities=[0.1, 0.5, 0.9],
    )

    errand_counts = [
        sum(1 for slot in calendar if isinstance(slot, dict) and "errand_id" in slot)
        for calendar in scenario["calendars"]
    ]

    assert scenario["agent_densities"] == [0.1, 0.5, 0.9]
    assert errand_counts == [1, 5, 9]


def test_groupchat_protocol_delivers_messages_to_all_task_agents_and_scores_mixed_team():
    config = CalendarGameConfig(
        seed=1,
        num_agents=3,
        num_slots=4,
        num_meetings=1,
        communication_protocol="groupchat",
        max_turns_per_round=2,
        enable_fallback=False,
        agents=[
            {"type": "llm", "model": "model-a"},
            {"type": "llm", "model": "model-b"},
            {"type": "llm", "model": "model-b"},
        ],
    )
    game = CalendarGame(config, dry_run=True)
    scenario = {
        "seed": 1,
        "num_agents": 3,
        "num_slots": 4,
        "calendars": [[None, None, None, None] for _ in range(3)],
        "meetings": [{
            "id": 1,
            "participants": [0, 1],
            "speaker_order": [0, 1],
            "duration": 1,
            "cost": 1,
        }],
        "optimal": {"cost": 0, "assignments": {"1": 0}},
        "greedy": {"cost": 0, "assignments": {"1": 0}},
        "feasible": True,
    }
    clients = [
        OneShotGroupchatFixedSlotClient(0, content="slot 0 works for me"),
        OneShotGroupchatFixedSlotClient(0),
        OneShotGroupchatFixedSlotClient(0),
    ]
    agents: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(config.num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents.append(agent)

    trace = game._run_with_agents(agents, scenario)

    groupchat_events = events_of_type(trace, "all_groupchat_sent")
    assert len(groupchat_events) == 1
    assert groupchat_events[0]["data"]["to_agents"] == [1, 2]
    assert clients[1].received_messages[0]["channel"] == "all_groupchat"
    assert clients[2].received_messages[0]["content"] == "slot 0 works for me"
    assert trace.metrics["total_groupchat_messages_sent"] == 1
    assert trace.metrics["total_all_groupchat_messages_sent"] == 1
    assert trace.metrics["total_dms_sent"] == 0
    assert trace.metrics["is_heterogeneous_team"] is True
    assert trace.metrics["team_model_counts"] == {"model-a": 1, "model-b": 2}
    assert len(trace.final_state["contribution_scores"]) == 3
    assert trace.final_state["contribution_scores"][0]["model"] == "model-a"


def test_dm_and_groupchat_protocol_allows_both_message_types():
    config = CalendarGameConfig(
        seed=1,
        num_agents=3,
        num_slots=4,
        num_meetings=1,
        communication_protocol="dm_and_groupchat",
        max_turns_per_round=2,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    scenario = {
        "seed": 1,
        "num_agents": 3,
        "num_slots": 4,
        "calendars": [[None, None, None, None] for _ in range(3)],
        "meetings": [{
            "id": 1,
            "participants": [0, 1, 2],
            "speaker_order": [0, 1, 2],
            "duration": 1,
            "cost": 1,
        }],
        "optimal": {"cost": 0, "assignments": {"1": 0}},
        "greedy": {"cost": 0, "assignments": {"1": 0}},
        "feasible": True,
    }
    clients = [
        OneShotMixedChatFixedSlotClient(0, dm_target=1),
        OneShotMixedChatFixedSlotClient(0),
        OneShotMixedChatFixedSlotClient(0),
    ]
    agents: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(config.num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents.append(agent)

    trace = game._run_with_agents(agents, scenario)

    groupchat_events = events_of_type(trace, "all_groupchat_sent")
    dm_events = events_of_type(trace, "dm_sent")
    assert len(groupchat_events) == 3
    assert len(dm_events) == 1
    assert trace.metrics["total_groupchat_messages_sent"] == 3
    assert trace.metrics["total_dms_sent"] == 1
    assert any(message["channel"] == "all_groupchat" for message in clients[1].received_messages)
    assert any(message["channel"] == "dm" for message in clients[1].received_messages)
    assert trace.metrics["total_cheap_talk_messages"] == 4


def test_participant_groupchat_reaches_only_meeting_participants():
    config = CalendarGameConfig(
        seed=1,
        num_agents=3,
        num_slots=4,
        num_meetings=1,
        communication_protocol="participant_groupchat",
        max_turns_per_round=2,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    scenario = {
        "seed": 1,
        "num_agents": 3,
        "num_slots": 4,
        "calendars": [[None, None, None, None] for _ in range(3)],
        "meetings": [{
            "id": 1,
            "participants": [0, 1],
            "speaker_order": [0, 1],
            "duration": 1,
            "cost": 1,
        }],
        "optimal": {"cost": 0, "assignments": {"1": 0}},
        "greedy": {"cost": 0, "assignments": {"1": 0}},
        "feasible": True,
    }
    clients = [
        OneShotGroupchatFixedSlotClient(
            0,
            content="participant-only slot 0 proposal",
            channel="participant_groupchat",
        ),
        OneShotGroupchatFixedSlotClient(0, channel="participant_groupchat"),
        OneShotGroupchatFixedSlotClient(0, channel="participant_groupchat"),
    ]
    agents: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(config.num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents.append(agent)

    trace = game._run_with_agents(agents, scenario)

    participant_events = events_of_type(trace, "participant_groupchat_sent")
    assert len(participant_events) == 1
    assert participant_events[0]["data"]["to_agents"] == [1]
    assert clients[1].received_messages[0]["channel"] == "participant_groupchat"
    assert clients[2].received_messages == []
    assert trace.metrics["total_participant_groupchat_messages_sent"] == 1
    assert trace.metrics["total_all_groupchat_messages_sent"] == 0


def test_trace_records_per_agent_oracle_cost_and_excess_burden():
    config = CalendarGameConfig(
        seed=1,
        num_agents=2,
        num_slots=3,
        num_meetings=1,
        max_turns_per_round=1,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    scenario = {
        "seed": 1,
        "num_agents": 2,
        "num_slots": 3,
        "calendars": [
            [None, None, None],
            [{"errand_id": 10, "cost": 4}, None, None],
        ],
        "meetings": [{
            "id": 1,
            "participants": [0, 1],
            "speaker_order": [0, 1],
            "duration": 1,
            "cost": 1,
        }],
        "optimal": {"cost": 0, "assignments": {"1": 1}},
        "greedy": {"cost": 4, "assignments": {"1": 0}},
        "feasible": True,
    }
    clients: list[BaseClient] = [
        FixedBatchClient([{"type": "schedule", "slot": 0}]),
        FixedBatchClient([
            {"type": "reschedule", "item_id": 10, "from_slot": 0, "to_slot": 2},
            {"type": "schedule", "slot": 0},
        ]),
    ]
    agents: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(config.num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents.append(agent)

    trace = game._run_with_agents(agents, scenario)

    assert trace.metrics["realized_cost"] == 4
    assert trace.metrics["optimal_cost"] == 0
    assert trace.final_state["per_agent_cost"] == [0, 4]
    assert trace.final_state["oracle_per_agent_cost"] == [0, 0]
    assert trace.final_state["per_agent_excess_burden"] == [0, 4]
    assert trace.metrics["total_excess_burden"] == 4
    assert trace.final_state["contribution_scores"][1]["excess_burden"] == 4


def test_phase_ordering():
    """All CHEAP_TALK turns appear before DECISION events, which appear before RESOLUTION."""
    trace = run_dry()

    events = _normalize(trace.events)
    event_types = [e["type"] for e in events]

    # Find last cheap_talk turn index and first decide index
    last_cheap_talk_idx = -1
    first_decide_idx = len(event_types)
    first_resolution_idx = len(event_types)

    for i, e in enumerate(events):
        if e["type"] in ("turn_start", "turn_end") and e["data"].get("phase") == "CHEAP_TALK":
            last_cheap_talk_idx = i
        if e["type"] in ("decide_start", "decide_end") and first_decide_idx == len(event_types):
            first_decide_idx = i
        if e["type"] == "resolution" and first_resolution_idx == len(event_types):
            first_resolution_idx = i

    assert last_cheap_talk_idx < first_decide_idx, (
        f"CHEAP_TALK turn at idx {last_cheap_talk_idx} not before DECISION at {first_decide_idx}"
    )
    assert first_decide_idx < first_resolution_idx, (
        f"DECISION at idx {first_decide_idx} not before RESOLUTION at {first_resolution_idx}"
    )


def test_dm_delivery_is_bounded_by_turn_cap_not_dm_cap():
    """DMs are not rejected by dm_cap; cheap-talk is bounded by max_turns_per_round."""
    # Keep dm_cap=1 to verify it is no longer enforced.
    # Agent 0 tries to send 3 DMs to agent 1 each turn.
    dm_client = AlwaysDMClient(target_id=1, num_dms=3)
    # Agent 1 uses a scripted client that passes
    scripted_client = ScriptedClient()

    trace, agents = _run_with_clients(
        [dm_client, scripted_client],
        dm_cap=1,
        max_turns_per_round=3,
    )

    dm_rejected = events_of_type(trace, "dm_rejected")
    assert len(dm_rejected) == 0, "DMs should not be rejected by dm_cap"

    dm_sent = events_of_type(trace, "dm_sent")
    assert len(dm_sent) > 1, "Expected multiple DMs to be delivered despite dm_cap=1"

    # Agent 0 should still have turn_start events after cap was exceeded
    turn_starts_agent0 = [e for e in _normalize(trace.events)
                          if e["type"] == "turn_start" and e["data"]["agent_id"] == 0]
    # At least 2 turns because delivered DMs keep cheap-talk active until the turn cap.
    assert len(turn_starts_agent0) >= 2, (
        f"Expected >=2 turn_starts for agent 0, got {len(turn_starts_agent0)}"
    )

    # Calendar of agent 0 should not have any meeting marker corruption
    for slot in agents[0].calendar.slots:
        assert slot is None or isinstance(slot, dict) or isinstance(slot, str), \
            f"Unexpected slot type: {type(slot)}"


def test_decision_simultaneous():
    """Both decide_start events show pre-decision calendar state (no M1 markers)."""
    trace = run_dry()

    decide_starts = events_of_type(trace, "decide_start")
    assert len(decide_starts) >= 2, "Expected at least 2 decide_start events for 2-agent game"

    for event in decide_starts:
        snapshot = event["data"]["calendar_snapshot_render"]
        assert "M1" not in snapshot, (
            f"Agent {event['data']['agent_id']} decide_start snapshot already contains M1; "
            "decisions are not simultaneous"
        )


def test_decision_atomicity():
    """Invalid batch with duplicate target slot does not mutate calendar."""
    cal = Calendar(num_slots=8)
    cal.slots = [{"errand_id": 1, "cost": 1}, None, None, None, None, None, None, None]

    # Two actions both targeting slot 2 - violates Rule 2
    actions = [
        {"type": "reschedule", "item_id": 1, "from_slot": 0, "to_slot": 2},
        {"type": "schedule", "meeting_id": 1, "slot": 2},
    ]

    ok, reason = validate_batch(cal, actions)
    assert not ok, "Expected invalid batch for duplicate target slot"
    assert "2" in reason, f"Expected slot 2 in conflict reason, got: {reason}"

    # Calendar must be completely unchanged
    assert cal.slots[0] == {"errand_id": 1, "cost": 1}, "Slot 0 was mutated during failed validation"
    assert cal.slots[2] is None, "Slot 2 was mutated during failed validation"


def test_decision_retry_exhaustion():
    """With decision_retries=2, invalid batches produce 3 batch_rejected + 1 decision_failed per agent."""
    invalid_client_0 = InvalidBatchClient(meeting_id=1)
    invalid_client_1 = InvalidBatchClient(meeting_id=1)

    trace, agents = _run_with_clients(
        [invalid_client_0, invalid_client_1],
        decision_retries=2,
        num_slots=16,
    )

    # Each agent produces batch_rejected events
    norm = _normalize(trace.events)
    for agent_id in [0, 1]:
        rejected = [e for e in norm
                    if e["type"] == "batch_rejected" and e["data"]["agent_id"] == agent_id]
        # initial attempt + 2 retries = 3 rejections
        assert len(rejected) == 3, (
            f"Agent {agent_id}: expected 3 batch_rejected events, got {len(rejected)}"
        )

        failed = [e for e in norm
                  if e["type"] == "decision_failed" and e["data"]["agent_id"] == agent_id]
        assert len(failed) == 1, (
            f"Agent {agent_id}: expected 1 decision_failed event, got {len(failed)}"
        )

        # Calendar should not contain the meeting marker
        cal_slots = agents[agent_id].calendar.slots
        assert "M1" not in cal_slots, (
            f"Agent {agent_id} calendar contains M1 despite failed decision"
        )


def test_inbox_empty_at_decision():
    """No DMs are sent during the DECISION phase."""
    trace = run_dry()

    dm_sent_events = events_of_type(trace, "dm_sent")
    for event in dm_sent_events:
        phase = event["data"].get("phase")
        assert phase != "DECISION", (
            f"Found dm_sent event during DECISION phase: {event}"
        )


def test_non_participant_queued_once():
    """Non-participant agent 2 gets at most one turn_start per round even if DM'd twice."""
    # 3-agent game; agent 0 DMs agent 2 twice per turn
    # meeting participants will be agents 0 and 1 (default generate_scenario for 3 agents all participate)
    # We need only agents 0 and 1 as participants; use participant_lists to control this
    # Since CalendarGame doesn't support participant_lists directly, we'll use _run_with_clients
    # with 2 participants and 3 agents. The scenario generator includes all agents by default.
    # Instead: run 3 agents with default (all participate) — agent 2 is a participant.
    # We need a non-participant scenario. Let's create the game with 3 agents but only agents 0+1 meet.
    # We can't easily do this via CalendarGame alone, so we'll verify the count principle
    # by running a 2-agent game and confirming the basic queuing behavior, then test
    # with a manual run that uses participant_lists.

    # Manual approach: run the game loop manually with participant_lists=[0,1] for 3 agents
    num_agents = 3
    seed = 42
    num_slots = 16
    decision_retries = 0

    # agent 0 sends 2 DMs to agent 2 on first turn; agent 1 is scripted
    clients = [AlwaysDMClient(target_id=2, num_dms=2), ScriptedClient(), ScriptedClient()]

    scenario = generate_scenario(
        seed=seed, num_agents=num_agents, num_slots=num_slots,
        density=0.5, pref_level=1, num_meetings=1,
        participant_lists=[[0, 1]],  # only agents 0 and 1 participate
    )

    agents_list: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(num_slots=num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agents_list.append(agent)

    all_agent_ids = list(range(num_agents))
    for agent_id, agent in enumerate(agents_list):
        gc = GameConfig(
            num_agents=num_agents, num_slots=num_slots, agent_id=agent_id,
            all_agent_ids=all_agent_ids, decision_retries=decision_retries,
        )
        agent.register(agent_id, gc)

    events = EventLog()
    meeting = scenario["meetings"][0]  # participants = [0, 1]

    for agent_id in meeting["participants"]:
        agents_list[agent_id].start_round(meeting, 0)

    already_queued: set[int] = set()
    turn_index = 0

    has_activity = True
    while has_activity and turn_index < 5:
        has_activity = False

        for agent_id in meeting["participants"]:
            inbox_snapshot = list(agents_list[agent_id].inbox_queue)
            events.append("turn_start", data={
                "round": 0, "turn": turn_index, "phase": "CHEAP_TALK",
                "agent_id": agent_id, "inbox_drained": inbox_snapshot,
            })
            result = agents_list[agent_id].turn(turn_index, 5)
            events.append("turn_end", data={
                "round": 0, "turn": turn_index, "phase": "CHEAP_TALK",
                "agent_id": agent_id, "tool_calls": result.tool_calls,
                "text": result.text, "thinking": result.thinking, "usage": None,
                "latency_ms": result.latency_ms, "raw_api_response": result.raw,
            })

            for tool in result.tool_calls:
                if tool.get("type") != "dm":
                    continue
                to = int(tool["to"])
                msg = {"from": agent_id, "meeting_id": tool.get("meeting_id", meeting["id"]),
                       "content": str(tool.get("content", ""))}
                agents_list[to].inbox_queue.append(msg)
                has_activity = True
                if to not in meeting["participants"] and to not in already_queued:
                    already_queued.add(to)

        queue = list(already_queued - set(meeting["participants"]))
        for agent_id in queue:
            inbox_snapshot = list(agents_list[agent_id].inbox_queue)
            events.append("turn_start", data={
                "round": 0, "turn": turn_index, "phase": "CHEAP_TALK",
                "agent_id": agent_id, "inbox_drained": inbox_snapshot,
            })
            result = agents_list[agent_id].turn(turn_index, 5)
            events.append("turn_end", data={
                "round": 0, "turn": turn_index, "phase": "CHEAP_TALK",
                "agent_id": agent_id, "tool_calls": result.tool_calls,
                "text": result.text, "thinking": result.thinking, "usage": None,
                "latency_ms": result.latency_ms, "raw_api_response": result.raw,
            })
            for tool in result.tool_calls:
                if tool.get("type") != "dm":
                    continue
                to = int(tool["to"])
                msg = {"from": agent_id, "meeting_id": tool.get("meeting_id", meeting["id"]),
                       "content": str(tool.get("content", ""))}
                agents_list[to].inbox_queue.append(msg)
                has_activity = True

        # Non-participants are only queued once per round (set semantics)
        already_queued = already_queued  # set already prevents re-adding
        turn_index += 1

    # Count turn_start events for agent 2 (non-participant who received 2 DMs in one turn)
    all_events = _normalize(events.all())
    turn_starts_agent2 = [e for e in all_events
                          if e["type"] == "turn_start" and e["data"]["agent_id"] == 2]

    # Agent 2 should appear in at most 1 turn_start per round tick
    # In round tick 0, agent 0 sends 2 DMs to agent 2. Agent 2 should only get 1 turn.
    # We check that there's exactly 1 turn_start for agent 2 in turn_index=0
    turn_0_starts_agent2 = [e for e in turn_starts_agent2 if e["data"]["turn"] == 0]
    assert len(turn_0_starts_agent2) == 1, (
        f"Agent 2 got {len(turn_0_starts_agent2)} turn_starts at turn 0, expected exactly 1"
    )


def test_non_participant_gets_followup_turn_after_nonparticipant_reply():
    """If non-participant A receives a DM back from B, A drains it on a later turn."""
    num_agents = 4
    num_slots = 16
    scenario = generate_scenario(
        seed=42, num_agents=num_agents, num_slots=num_slots,
        density=0.2, pref_level=1, num_meetings=1,
        participant_lists=[[0, 1]],
    )

    clients: list[BaseClient] = [
        OneShotDMClient(target_id=2, content="ask A", trigger="first_turn"),
        FixedSlotClient(slot=0),
        OneShotDMClient(target_id=3, content="ask B", trigger="on_message"),
        OneShotDMClient(target_id=2, content="reply A", trigger="on_message"),
    ]

    agents_list: list[Agent] = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(num_slots=num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=num_agents,
            num_slots=num_slots,
            agent_id=agent_id,
            all_agent_ids=list(range(num_agents)),
            dm_cap=100,
            decision_retries=0,
        ))
        agents_list.append(agent)

    game = CalendarGame(
        CalendarGameConfig(
            seed=42,
            num_agents=num_agents,
            num_slots=num_slots,
            num_meetings=1,
            max_turns_per_round=5,
            decision_retries=0,
            enable_fallback=False,
        ),
        dry_run=True,
    )
    trace = game._run_with_agents(agents_list, scenario)
    events = _normalize(trace.events)

    agent2_turns = [
        e for e in events
        if e["type"] == "turn_start" and e["data"]["phase"] == "CHEAP_TALK" and e["data"]["agent_id"] == 2
    ]
    assert any(
        any(msg["from"] == 3 and msg["content"] == "reply A" for msg in e["data"]["inbox_drained"])
        for e in agent2_turns
    ), f"Agent 2 never got a follow-up turn with agent 3's reply: {agent2_turns}"


def test_resolution_mismatch():
    """Two agents scheduling meeting at different slots produces coordinated=False."""
    # Agent 0 schedules at slot 3, agent 1 at slot 7
    # We need both slots to be free on agent calendars.
    # Use a scenario with many free slots and num_slots=16.
    slot_a = 0  # agent 0 picks this
    slot_b = 1  # agent 1 picks this (different)

    # Find slots that are actually free using density=0 (all free)
    client_0 = FixedSlotClient(slot=slot_a)
    client_1 = FixedSlotClient(slot=slot_b)

    trace, agents = _run_with_clients(
        [client_0, client_1],
        seed=42,
        num_slots=16,
        num_meetings=1,
        decision_retries=0,
    )

    resolution_events = events_of_type(trace, "resolution")
    assert len(resolution_events) == 1

    res = resolution_events[0]["data"]

    # It's possible slots 0 and 1 are not free (have errands) causing validation to fail
    # In that case decision_failed occurs and per_agent_slot will be None for both
    # Let's check what actually happened
    per_agent_slot = res["per_agent_slot"]

    # If both agents successfully placed their meeting markers at different slots, coordinated=False
    # If one or both failed, coordinated should also be False (no meeting placed)
    assert not res["coordinated"] or (
        per_agent_slot.get("0") == per_agent_slot.get("1") and per_agent_slot.get("0") is not None
    ), f"Expected not coordinated or same slot, got per_agent_slot={per_agent_slot}"

    # Actually for the mismatch test: run with density=0 to ensure free slots
    client_0b = FixedSlotClient(slot=slot_a)
    client_1b = FixedSlotClient(slot=slot_b)

    trace2, _ = _run_with_clients(
        [client_0b, client_1b],
        seed=42,
        num_slots=16,
        num_meetings=1,
        decision_retries=0,
    )
    # Override density by checking if agents used different slots
    res2 = events_of_type(trace2, "resolution")[0]["data"]
    # Since slots 0 and 1 might have errands at density=0.5, check if decision_failed or mismatch
    if res2["per_agent_slot"].get("0") is not None and res2["per_agent_slot"].get("1") is not None:
        assert not res2["coordinated"], "Agents at different slots should not be coordinated"
        assert res2["per_agent_slot"]["0"] != res2["per_agent_slot"]["1"]


def test_resolution_slot_conflict():
    """Two meetings scheduled at same slot by same agent appear in slot_conflicts."""
    # Run a 2-round game where both clients always schedule at slot 0
    # This will create conflict: M1 and M2 both at slot 0
    # We need 2 different meetings. With num_meetings=2, two rounds occur.
    # Both agents always schedule at slot 0 for both meetings.
    # On round 2, slot 0 already has M1, so FixedSlotClient(0) tries to put M2 at 0 too.
    # validate_batch will reject it (slot occupied) unless there's a reschedule.
    # So the "two meetings in same slot" via normal validation cannot happen normally.
    # Test the resolution checker directly with a manually crafted calendar state.

    # Build a simple 2-agent 2-meeting game and check slot_conflicts logic
    # We'll manually set up calendars with two M markers in same slot
    # by calling resolution logic directly from the game code.

    # Simulate: agent 0 has M1 and M2 both "at slot 3" by directly placing them
    cal = Calendar(num_slots=8)
    # Place two meeting markers - this tests the slot_conflict detection
    cal.slots[3] = "M1"
    # Can't have two values in same slot naturally, but detection looks for >1 'M' per slot
    # The actual slot_conflicts detection in game.py uses seen[slot_idx] which is a list
    # It appends each "M*" string per slot, so we need to manually test that path
    # by simulating what game.py does

    slot_conflicts: dict[str, list[int]] = {}
    seen: dict[int, list] = {}
    for slot_idx, slot_val in enumerate(cal.slots):
        if isinstance(slot_val, dict) and "meeting_id" in slot_val:
            seen.setdefault(slot_idx, []).append(f"M{slot_val['meeting_id']}")
    conflicts = [slot_idx for slot_idx, vals in seen.items() if len(vals) > 1]
    if conflicts:
        slot_conflicts["0"] = conflicts

    # With only M1 at slot 3, no conflicts
    assert len(conflicts) == 0, "Single meeting marker should not produce conflicts"

    # Now simulate two markers at same slot (as if state corruption occurred)
    # We do this by manually building the seen dict as game.py would
    seen2: dict[int, list] = {}
    for slot_idx, items in enumerate([{"meeting_id": 1, "cost": 1}, None, None, {"meeting_id": 2, "cost": 1}, None, None, None, None]):
        if items is None:
            continue
        if isinstance(items, dict) and "meeting_id" in items:
            seen2.setdefault(slot_idx, []).append(f"M{items['meeting_id']}")
    # Inject duplicate at slot 3
    seen2[3] = ["M1", "M2"]  # two meetings at same slot
    conflicts2 = [slot_idx for slot_idx, vals in seen2.items() if len(vals) > 1]
    assert 3 in conflicts2, "Expected slot 3 in slot_conflicts when two meetings share the slot"


def test_inbox_persists_across_rounds():
    """DMs are delivered: agent 1's inbox is drained on its turn_start with the message inside."""
    trace = run_dry(seed=42, num_meetings=1)

    # In dry_run, ScriptedClient sends a DM from agent 0 to agent 1 on first turn.
    # Check that dm_sent appears and the DM content reaches agent 1's turn_start inbox_drained.
    dm_sent_events = events_of_type(trace, "dm_sent")
    if not dm_sent_events:
        pytest.skip("No DMs were sent in this run; seed produces no free-slot DMs")

    # Find a DM sent from agent 0 to agent 1
    dm = next((e for e in dm_sent_events if e["data"]["from_agent"] == 0 and e["data"]["to_agent"] == 1), None)
    if dm is None:
        pytest.skip("No DM from agent 0 to agent 1 in this run")

    # Find the dm_sent event's position in the normalized list, then look for
    # agent 1's turn_start that comes *after* it in list order (same or later turn).
    norm = _normalize(trace.events)
    dm_pos = next(
        i for i, e in enumerate(norm)
        if e["type"] == "dm_sent"
        and e["data"].get("from_agent") == 0
        and e["data"].get("to_agent") == 1
    )

    subsequent_turn_starts = [
        e for e in norm[dm_pos + 1:]
        if e["type"] == "turn_start" and e["data"]["agent_id"] == 1
    ]

    if not subsequent_turn_starts:
        pytest.skip("No turn_start for agent 1 after the DM was sent")

    # The first subsequent turn_start for agent 1 should show the DM in inbox_drained
    next_turn = subsequent_turn_starts[0]
    inbox = next_turn["data"]["inbox_drained"]
    assert len(inbox) > 0, (
        f"Expected agent 1's inbox to contain the DM at turn {next_turn['data']['turn']}, "
        f"but inbox_drained is empty"
    )
    assert any(msg["from"] == 0 for msg in inbox), (
        f"Expected a message from agent 0 in agent 1's inbox, got: {inbox}"
    )


class VoluntaryRescheduleClient(BaseClient):
    """Non-participant client that performs a reschedule in the voluntary phase."""
    def __init__(self, from_slot: int, to_slot: int, item_id: int):
        self.from_slot = from_slot
        self.to_slot = to_slot
        self.item_id = item_id
        self.voluntary_called = False

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        pass

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def voluntary_decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        self.voluntary_called = True
        return DecideResult(
            tool_calls=[{"type": "reschedule", "item_id": self.item_id, "from_slot": self.from_slot, "to_slot": self.to_slot}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )


def test_voluntary_reschedule_phase():
    """Non-participant who received a DM gets a VOLUNTARY phase and can reschedule."""
    num_agents = 3
    num_slots = 16
    seed = 42

    scenario = generate_scenario(
        seed=seed, num_agents=num_agents, num_slots=num_slots,
        density=0.5, pref_level=1, num_meetings=1,
        participant_lists=[[0, 1]],  # agent 2 is non-participant
    )

    # Find a slot with an errand on agent 2's calendar to reschedule
    cal2 = scenario["calendars"][2]
    errand_slot = next((i for i, s in enumerate(cal2) if isinstance(s, dict) and "errand_id" in s), None)
    free_slot = next((i for i, s in enumerate(cal2) if s is None and i != errand_slot), None)
    assert errand_slot is not None and free_slot is not None, "Need an errand and a free slot on agent 2's calendar"
    item_id = cal2[errand_slot]["errand_id"]

    voluntary_client = VoluntaryRescheduleClient(from_slot=errand_slot, to_slot=free_slot, item_id=item_id)

    # agent 0 DMs agent 2 to trigger the voluntary phase
    clients = [AlwaysDMClient(target_id=2, num_dms=1), FixedSlotClient(slot=0), voluntary_client]

    # Build agents manually with custom clients
    all_agent_ids = list(range(num_agents))
    agents_list = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(num_slots=num_slots)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=num_agents, num_slots=num_slots,
            agent_id=agent_id, all_agent_ids=all_agent_ids,
            dm_cap=100, decision_retries=0,
        ))
        agents_list.append(agent)

    game, _ = _build_game_with_clients(clients, seed=seed, num_slots=num_slots)
    trace = game._run_with_agents(agents_list, scenario)
    trace_events = [{"type": e.type, "data": e.data} for e in trace.events]

    # voluntary_decide should have been called on agent 2
    assert voluntary_client.voluntary_called, "voluntary_decide was not called on non-participant"

    # VOLUNTARY phase events should be present
    voluntary_starts = [e for e in trace_events if e["type"] == "decide_start" and e["data"]["phase"] == "VOLUNTARY"]
    assert len(voluntary_starts) == 1
    assert voluntary_starts[0]["data"]["agent_id"] == 2

    # The reschedule should have been applied
    batch_applied = [e for e in trace_events if e["type"] == "batch_applied" and e["data"]["phase"] == "VOLUNTARY"]
    assert len(batch_applied) == 1

    # Agent 2's calendar should reflect the move: errand gone from errand_slot, present at free_slot
    assert not (isinstance(agents_list[2].calendar.get(errand_slot), dict) and
                "errand_id" in agents_list[2].calendar.get(errand_slot, {}))
    assert isinstance(agents_list[2].calendar.get(free_slot), dict)


# ---------------------------------------------------------------------------
# Clients for meeting-registry / consistency tests
# ---------------------------------------------------------------------------

class PerMeetingDecideClient(BaseClient):
    """Decides based on a per-meeting-id map of tool_calls."""
    def __init__(self, decide_map: dict, dm_map: dict | None = None):
        # decide_map: {meeting_id: [tool_call, ...]}
        # dm_map: {meeting_id: [dm tool_call, ...]} — sent on first CHEAP_TALK turn
        self.decide_map = decide_map
        self.dm_map = dm_map or {}
        self._current_meeting: dict | None = None
        self._first_turn = True

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        self._current_meeting = meeting
        self._first_turn = True

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        if self._first_turn and self._current_meeting is not None:
            self._first_turn = False
            tool_calls = self.dm_map.get(self._current_meeting["id"], [])
            return TurnResult(tool_calls=tool_calls, text=None, thinking=None, usage=None, latency_ms=None, raw=None)
        self._first_turn = False
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(
            tool_calls=self.decide_map.get(meeting["id"], []),
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def voluntary_decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)


def test_blocked_reschedule_fails_resolution_and_rolls_back_staged_batches():
    """If one participant tries to move a blocked errand, no participant batch commits."""
    scenario = {
        "seed": 1,
        "num_agents": 2,
        "num_slots": 4,
        "calendars": [
            [{"errand_id": 1, "cost": 1, "blocked": True}, None, None, None],
            [None, None, None, None],
        ],
        "meetings": [{"id": 1, "participants": [0, 1], "speaker_order": [0, 1], "duration": 1, "cost": 1}],
        "optimal": {"cost": 0, "assignments": {"1": 1}},
        "greedy": {"cost": 0, "assignments": {"1": 1}},
        "feasible": True,
    }
    clients = [
        PerMeetingDecideClient(decide_map={
            1: [
                {"type": "reschedule", "item_id": 1, "from_slot": 0, "to_slot": 1},
                {"type": "schedule", "meeting_id": 1, "slot": 0},
            ],
        }),
        PerMeetingDecideClient(decide_map={
            1: [{"type": "schedule", "meeting_id": 1, "slot": 0}],
        }),
    ]
    config = CalendarGameConfig(
        seed=1,
        num_agents=2,
        num_slots=4,
        num_meetings=1,
        density=0,
        decision_retries=0,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    agents_list = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(num_slots=4)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=2, num_slots=4, agent_id=agent_id,
            all_agent_ids=[0, 1], dm_cap=100, decision_retries=0,
        ))
        agents_list.append(agent)

    trace = game._run_with_agents(agents_list, scenario)
    ev = [{"type": e.type, "data": e.data} for e in trace.events]

    resolution = next(e for e in ev if e["type"] == "resolution")
    assert not resolution["data"]["coordinated"]
    assert resolution["data"]["blocked_slot_violations"]
    assert resolution["data"]["blocked_slot_violations"][0]["kind"] == "blocked_reschedule"
    assert agents_list[1].calendar.get(0) is None
    assert any(e["type"] == "batch_rolled_back" and e["data"]["agent_id"] == 1 for e in ev)


def test_meeting_on_blocked_slot_fails_resolution():
    """Resolution rejects any meeting marker already overlapping a blocked slot."""
    scenario = {
        "seed": 1,
        "num_agents": 1,
        "num_slots": 2,
        "calendars": [[{"meeting_id": 99, "cost": 1, "blocked": True}, None]],
        "meetings": [{"id": 1, "participants": [0], "speaker_order": [0], "duration": 1, "cost": 1}],
        "optimal": {"cost": 0, "assignments": {"1": 1}},
        "greedy": {"cost": 0, "assignments": {"1": 1}},
        "feasible": True,
    }
    client = PerMeetingDecideClient(decide_map={
        1: [{"type": "schedule", "meeting_id": 1, "slot": 1}],
    })
    agent = Agent(client)
    cal = Calendar(num_slots=2)
    cal.slots = list(scenario["calendars"][0])
    agent.calendar = cal
    agent.register(0, GameConfig(
        num_agents=1, num_slots=2, agent_id=0,
        all_agent_ids=[0], dm_cap=100, decision_retries=0,
    ))
    game = CalendarGame(
        CalendarGameConfig(
            seed=1,
            num_agents=1,
            num_slots=2,
            num_meetings=1,
            density=0,
            decision_retries=0,
            enable_fallback=False,
        ),
        dry_run=True,
    )

    trace = game._run_with_agents([agent], scenario)
    resolution = next(e for e in trace.events if e.type == "resolution")

    assert not resolution.data["coordinated"]
    assert any(
        violation["kind"] == "meeting_on_blocked_slot"
        for violation in resolution.data["blocked_slot_violations"]
    )


class VoluntaryMeetingRescheduleClient(BaseClient):
    """Non-participant that reschedules a shared meeting in the VOLUNTARY phase."""
    def __init__(self, meeting_id: int, from_slot: int, to_slot: int):
        self.meeting_id = meeting_id
        self.from_slot = from_slot
        self.to_slot = to_slot
        self.voluntary_called = False

    def register(self, agent_id: int, game_config: GameConfig) -> None:
        pass

    def start_round(self, meeting: dict, calendar_render: str, round_num: int) -> None:
        pass

    def turn(self, messages: list[dict], turn_index: int | None = None, max_turns_per_round: int | None = None) -> TurnResult:
        return TurnResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def retry_decide(self, attempt: int, max_attempts: int, conflict: str) -> DecideResult:
        return DecideResult(tool_calls=[], text=None, thinking=None, usage=None, latency_ms=None, raw=None)

    def voluntary_decide(self, meeting: dict, calendar_render: str) -> DecideResult:
        self.voluntary_called = True
        return DecideResult(
            tool_calls=[{"type": "reschedule", "item_id": self.meeting_id,
                         "from_slot": self.from_slot, "to_slot": self.to_slot}],
            text=None, thinking=None, usage=None, latency_ms=None, raw=None,
        )


def _build_two_meeting_scenario(num_slots: int = 16):
    """Return a scenario with 3 agents, 2 meetings, density=0 (all free slots)."""
    return generate_scenario(
        seed=1, num_agents=3, num_slots=num_slots,
        density=0, pref_level=1, num_meetings=2,
        participant_lists=[[0, 1], [0, 2]],
        errand_cost_level=10, meeting_cost_level=1,
    )


def test_consistency_violation_on_unilateral_initial_prior_meeting_reschedule():
    """
    Initial prior meetings must be consistency-checked too.

    Agent 0 and external agent 2 start with M100 at slot 0. Agent 0 moves only
    its local copy of M100, then agents 0/1/3 schedule M1 at slot 0. The round
    must fail because M100 no longer has a consistent shared slot.
    """
    scenario = {
        "seed": 1,
        "num_agents": 4,
        "num_slots": 16,
        "calendars": [
            [{"meeting_id": 100, "cost": 1}, None, None, None, None, None, None, None,
             None, None, None, None, None, None, None, None],
            [None] * 16,
            [{"meeting_id": 100, "cost": 1}, None, None, None, None, None, None, None,
             None, None, None, None, None, None, None, None],
            [None] * 16,
        ],
        "meetings": [{"id": 1, "participants": [0, 1, 3], "duration": 1, "cost": 1}],
        "prior_meetings": [{"id": 100, "participants": [0, 2], "slot": 0, "cost": 1}],
        "optimal": {"cost": 2, "assignments": {"1": 0, "100": 15}},
        "greedy": {"cost": 2, "assignments": {"1": 0}},
        "feasible": True,
    }

    clients = [
        PerMeetingDecideClient(decide_map={
            1: [
                {"type": "reschedule", "item_id": 100, "from_slot": 0, "to_slot": 14},
                {"type": "schedule", "meeting_id": 1, "slot": 0},
            ],
        }),
        PerMeetingDecideClient(decide_map={
            1: [{"type": "schedule", "meeting_id": 1, "slot": 0}],
        }),
        PerMeetingDecideClient(decide_map={}),
        PerMeetingDecideClient(decide_map={
            1: [{"type": "schedule", "meeting_id": 1, "slot": 0}],
        }),
    ]

    config = CalendarGameConfig(
        seed=1,
        num_agents=4,
        num_slots=16,
        num_meetings=1,
        density=0,
        decision_retries=0,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)

    all_agent_ids = [0, 1, 2, 3]
    agents_list = []
    for agent_id, client in enumerate(clients):
        agent = Agent(client)
        cal = Calendar(num_slots=16)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=4, num_slots=16, agent_id=agent_id,
            all_agent_ids=all_agent_ids, dm_cap=100, decision_retries=0,
        ))
        agents_list.append(agent)

    trace = game._run_with_agents(agents_list, scenario)
    ev = [{"type": e.type, "data": e.data} for e in trace.events]

    violations = [e for e in ev if e["type"] == "consistency_violation"]
    assert violations, "Expected consistency_violation for unilateral initial M100 reschedule"
    assert all(e["data"]["meeting_id"] == 100 for e in violations)

    resolution = next(e for e in ev if e["type"] == "resolution")
    assert not resolution["data"]["coordinated"]
    assert 100 in resolution["data"]["consistency_violated_meeting_ids"]
    assert trace.metrics["meetings_scheduled"] == 0


def test_prior_meeting_participants_are_rendered_in_prompts():
    """Prior meeting calendar entries should name co-participants for agents."""
    scenario = {
        "seed": 1,
        "num_agents": 4,
        "num_slots": 16,
        "calendars": [
            [{"meeting_id": 100, "cost": 1}, None, None, None, None, None, None, None,
             None, None, None, None, None, None, None, None],
            [None] * 16,
            [{"meeting_id": 100, "cost": 1}, None, None, None, None, None, None, None,
             None, None, None, None, None, None, None, None],
            [None] * 16,
        ],
        "meetings": [{"id": 1, "participants": [0, 1, 3], "duration": 1, "cost": 1}],
        "prior_meetings": [{"id": 100, "participants": [0, 2], "slot": 0, "cost": 1}],
        "optimal": {"cost": 2, "assignments": {"1": 0, "100": 15}},
        "greedy": {"cost": 2, "assignments": {"1": 0}},
        "feasible": True,
    }

    config = CalendarGameConfig(
        seed=1,
        num_agents=4,
        num_slots=16,
        num_meetings=1,
        density=0,
        decision_retries=0,
        enable_fallback=False,
    )
    game = CalendarGame(config, dry_run=True)
    trace = game.run_with_scenario(scenario)
    ev = [{"type": e.type, "data": e.data} for e in trace.events]

    agent0_registered = next(
        e for e in ev
        if e["type"] == "agent_registered" and e["data"]["agent_id"] == 0
    )
    assert "Meeting M100 (cost=1) participants=[0, 2]" in agent0_registered["data"]["calendar_render"]

    agent0_turn = next(
        e for e in ev
        if e["type"] == "turn_start" and e["data"]["agent_id"] == 0 and e["data"]["turn"] == 0
    )
    assert "Meeting M100 (cost=1) participants=[0, 2]" in agent0_turn["data"]["prompt_sent"]


def test_consistency_violation_on_unilateral_reschedule():
    """
    Agent 0 moves shared M1 unilaterally in round 2 (agent 1 does not).
    Expect consistency_violation events and coordinated=False for round 2.
    """
    M1_SLOT = 5
    M2_SLOT = 3
    M1_NEW_SLOT = 8

    scenario = _build_two_meeting_scenario()

    # Round 1: both agents 0+1 schedule M1 at slot 5
    # Round 2: agent 0 reschedules M1 (5→8) and schedules M2 at 5; agent 2 schedules M2 at 5
    # Agent 1 is non-participant in round 2 and receives no DM → does NOT move M1
    client0 = PerMeetingDecideClient(decide_map={
        1: [{"type": "schedule", "meeting_id": 1, "slot": M1_SLOT}],
        2: [
            {"type": "reschedule", "item_id": 1, "from_slot": M1_SLOT, "to_slot": M1_NEW_SLOT},
            {"type": "schedule", "meeting_id": 2, "slot": M2_SLOT},
        ],
    })
    client1 = PerMeetingDecideClient(decide_map={
        1: [{"type": "schedule", "meeting_id": 1, "slot": M1_SLOT}],
    })
    client2 = PerMeetingDecideClient(decide_map={
        2: [{"type": "schedule", "meeting_id": 2, "slot": M2_SLOT}],
    })

    config = CalendarGameConfig(seed=1, num_agents=3, num_slots=16, num_meetings=2,
                                density=0, decision_retries=0)
    game = CalendarGame(config, dry_run=True)

    all_agent_ids = [0, 1, 2]
    agents_list = []
    for agent_id, client in enumerate([client0, client1, client2]):
        agent = Agent(client)
        cal = Calendar(num_slots=16)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=3, num_slots=16, agent_id=agent_id,
            all_agent_ids=all_agent_ids, dm_cap=100, decision_retries=0,
        ))
        agents_list.append(agent)

    trace = game._run_with_agents(agents_list, scenario)
    ev = [{"type": e.type, "data": e.data} for e in trace.events]

    violations = [e for e in ev if e["type"] == "consistency_violation"]
    assert len(violations) > 0, "Expected consistency_violation events for unilateral M1 reschedule"
    assert all(e["data"]["meeting_id"] == 1 for e in violations)

    round2_resolution = next(
        e for e in ev if e["type"] == "resolution" and e["data"]["meeting_id"] == 2
    )
    assert not round2_resolution["data"]["coordinated"], (
        "Round 2 should not be coordinated when constraint B is violated"
    )
    assert 1 in round2_resolution["data"]["consistency_violated_meeting_ids"]


def test_voluntary_meeting_reschedule_satisfies_consistency():
    """
    Agent 0 DMs agent 1 to move M1 → agent 1 reschedules M1 in VOLUNTARY phase.
    Both agents move M1 to the same new slot → constraint B passes, M2 coordinates.
    """
    M1_SLOT = 5
    M2_SLOT = 3
    M1_NEW_SLOT = 8

    scenario = _build_two_meeting_scenario()

    # Round 1: agents 0+1 schedule M1 at slot 5
    # Round 2: agent 0 DMs agent 1; agent 1 gets VOLUNTARY and moves M1 5→8;
    #          agent 0 moves M1 5→8 + schedules M2 at 3; agent 2 schedules M2 at 3
    voluntary_client1 = VoluntaryMeetingRescheduleClient(
        meeting_id=1, from_slot=M1_SLOT, to_slot=M1_NEW_SLOT
    )
    client0 = PerMeetingDecideClient(
        decide_map={
            1: [{"type": "schedule", "meeting_id": 1, "slot": M1_SLOT}],
            2: [
                {"type": "reschedule", "item_id": 1, "from_slot": M1_SLOT, "to_slot": M1_NEW_SLOT},
                {"type": "schedule", "meeting_id": 2, "slot": M2_SLOT},
            ],
        },
        dm_map={2: [{"type": "dm", "to": 1, "meeting_id": 2, "content": "please move M1 to slot 8"}]},
    )
    client1 = PerMeetingDecideClient(decide_map={
        1: [{"type": "schedule", "meeting_id": 1, "slot": M1_SLOT}],
    })
    # Patch voluntary_decide on client1 to use voluntary_client1's logic
    client1.voluntary_decide = voluntary_client1.voluntary_decide  # type: ignore[method-assign]
    client2 = PerMeetingDecideClient(decide_map={
        2: [{"type": "schedule", "meeting_id": 2, "slot": M2_SLOT}],
    })

    config = CalendarGameConfig(seed=1, num_agents=3, num_slots=16, num_meetings=2,
                                density=0, decision_retries=0)
    game = CalendarGame(config, dry_run=True)

    all_agent_ids = [0, 1, 2]
    agents_list = []
    for agent_id, client in enumerate([client0, client1, client2]):
        agent = Agent(client)
        cal = Calendar(num_slots=16)
        cal.slots = list(scenario["calendars"][agent_id])
        agent.calendar = cal
        agent.register(agent_id, GameConfig(
            num_agents=3, num_slots=16, agent_id=agent_id,
            all_agent_ids=all_agent_ids, dm_cap=100, decision_retries=0,
        ))
        agents_list.append(agent)

    trace = game._run_with_agents(agents_list, scenario)
    ev = [{"type": e.type, "data": e.data} for e in trace.events]

    # No consistency violations
    violations = [e for e in ev if e["type"] == "consistency_violation"]
    assert len(violations) == 0, f"Unexpected consistency_violation: {violations}"

    # M2 round is coordinated
    round2_resolution = next(
        e for e in ev if e["type"] == "resolution" and e["data"]["meeting_id"] == 2
    )
    assert round2_resolution["data"]["coordinated"], "M2 should be coordinated after consistent M1 reschedule"

    # Both agents have M1 at M1_NEW_SLOT
    assert agents_list[0].calendar.get(M1_NEW_SLOT) == {"meeting_id": 1, "cost": 1}
    assert agents_list[1].calendar.get(M1_NEW_SLOT) == {"meeting_id": 1, "cost": 1}
    assert agents_list[0].calendar.get(M1_SLOT) is None
    assert agents_list[1].calendar.get(M1_SLOT) is None
