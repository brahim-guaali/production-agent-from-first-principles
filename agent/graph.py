"""The refund agent: a LangGraph graph, started in the graph-engineering course.

classify -> (order, policy, fraud, history in parallel) -> decide -> verify -> manager approval
if the amount is over $500 or the customer had 3+ refunds in 30 days -> refund (with an
idempotency key) -> reply, which leaves a note in the customer's history for the next run.
Every message passes an input guardrail (prompt injection), and the streamed reply an
output check (amount, currency) with a correction if it fails (stage 06).
Lookups retry transient errors and validate what they get; a lookup that still fails is
recorded in `failures` and the run escalates with a reply that says what went wrong
(stage 05). The refund reply is streamed to the customer's chat as it's written (stage 04).
A follow-up in a conversation ("why only $72?") goes to `explain`, which answers from the
session and the notes, or hands the customer to a person. Every run belongs to a session
(stage 02): the customer's message and the agent's reply are stored as turns.
Two sub-agents (stage 03): a grey-zone fraud score (0.4 to 0.7) is handed to `fraud_review`,
and `explain` asks `policy_expert` before answering. Each hand-off is recorded in `handoffs`.
Messages that aren't refund requests go to `support`, a small agent loop inside one node.
State is checkpointed in SQLite, so a run can pause for the manager and resume in another
process.
"""
import operator
import sqlite3
from pathlib import Path
from typing import Annotated, Optional, TypedDict

from langgraph.checkpoint.sqlite import SqliteSaver
from langgraph.graph import END, START, StateGraph
from langgraph.types import interrupt
from pydantic import ValidationError

from agentkit import judgments
from agentkit.trace import NullTracer
from agent import guardrails as gr
from agent import lookups as lk
from agent.subagents import FRAUD_REVIEW, POLICY_EXPERT
from agent.support import support_agent
from agent.verify import check

APPROVAL_LIMIT = 500
LOOKUPS = ["order", "policy", "fraud", "history"]
FREQUENT_CLAIMS = 3          # §8: refunds in the last 30 days that send any refund to a manager
MAX_ATTEMPTS = 3
DB = Path(__file__).resolve().parents[1] / "var" / "langgraph.db"


class RefundState(TypedDict, total=False):
    request: dict
    session: dict
    budget: Optional[float]
    claim: dict
    order: dict
    policy: dict
    fraud: dict
    history: dict
    fraud_review: dict
    handoffs: Annotated[list, operator.add]     # every call to a sub-agent, in order
    failures: Annotated[list, operator.add]     # lookups that failed after retries (stage 05)
    guardrails: Annotated[list, operator.add]   # input and output checks, pass or flagged (stage 06)
    evidence: Annotated[list, operator.add]     # three parallel writers: append
    spent: Annotated[float, operator.add]       # every model call adds its cost
    attempts: Annotated[int, operator.add]
    decision: dict
    problems: list
    approval_request: dict
    approval: str
    payment: dict
    reply: dict


def build(llm, platform, tracer=NullTracer(), db=DB):
    def traced(name, fn):
        """Report each node to the live viewer; LangGraph does the rest."""
        def node(state, config):
            tracer.node_started(name, round=config.get("metadata", {}).get("langgraph_step"))
            try:
                update = fn(state, config)
            except Exception as e:
                if type(e).__name__ == "GraphInterrupt":
                    tracer.node_waiting(name, "waiting for the operations manager")
                else:
                    tracer.node_failed(name, e)
                raise
            tracer.node_finished(name, update)
            return update
        return node

    def charged(call):
        before = llm.usage.cost
        out = call()
        return out, llm.usage.cost - before

    def run_id(config):
        return config["configurable"]["thread_id"]

    def session_of(s, config):
        return s["request"].get("session_id") or run_id(config)

    def say(s, config, text):
        """The agent's side of the conversation: a stored turn and a message to the customer."""
        r = s["request"]
        platform.add_turn(session_of(s, config), r["customer"], "agent", text, run_id(config))
        return platform.notify(r["customer"], text) | {"text": text}

    def session(s, config):
        r = s["request"]
        before = platform.get_session(session_of(s, config))
        platform.add_turn(session_of(s, config), r["customer"], "customer", r["message"], run_id(config))
        return {"session": before, "evidence": [f"session: {len(before['turns'])} earlier turns"]}

    def guard(s, config):
        before = llm.usage.cost
        events, used_model = gr.check_input(llm, s["request"]["message"])
        flagged = [e for e in events if e["verdict"] == "flagged"]
        if flagged:
            tracer.log(f"guardrail: prompt injection flagged by {flagged[0]['by']}: {flagged[0]['evidence']}")
        return {"guardrails": events, "spent": llm.usage.cost - before}

    def classify(s, config):
        claim, cost = charged(lambda: judgments.classify(llm, s["request"]["message"], s["session"]["turns"]))
        if claim.order_id:                           # customers type "a-9310" too (stage 07)
            claim.order_id = claim.order_id.strip().upper()
        return {"claim": claim.model_dump(), "spent": cost}

    def explain(s, config):
        r = s["request"]
        notes = platform.get_history(r["customer"])["notes"]
        handoff, cost1 = charged(lambda: POLICY_EXPERT.run(
            llm, platform, f"A customer asks: {r['message']!r}. Earlier in the conversation: "
            + " | ".join(f"{t['role']}: {t['text']}" for t in s["session"]["turns"][-4:]), "explain", tracer))
        e, cost = charged(lambda: judgments.explain(llm, r["message"], s["session"]["turns"], notes,
                                                    platform.get_policy(), handoff["result"]))
        cost += cost1
        reply = say(s, config, e.answer) | {"explanation": e.model_dump()}
        if e.wants_person:
            reply["ticket"] = platform.create_ticket(r["customer"], "other", "normal",
                                                     f"Disputes an earlier decision: {r['message'][:120]}")
        return {"reply": reply, "spent": cost, "handoffs": [handoff]}

    def looked_up(field, service, call, schema, describe):
        """A lookup node: fetch with retries and a schema check; a failure is data, not a crash."""
        value, failure, attempts = lk.fetch(service, call, schema, tracer)
        if failure:
            return {"failures": [failure], "evidence": [f"{service}: FAILED ({failure['kind']}, "
                                                        f"{failure['attempts']} attempts)"]}
        retried = f" after {attempts} attempts" if attempts > 1 else ""
        return {field: value, "evidence": [describe(value) + retried]}

    def order(s, config):
        return looked_up("order", "orders", lambda: platform.get_order(s["claim"]["order_id"]), lk.Order,
                         lambda o: f"order {o['order_id']}: ${o['total']}, {o['minutes_late']} min late")

    def policy(s, config):
        return looked_up("policy", "policy", platform.get_policy, lk.Policy, lambda p: f"policy {p['version']}")

    def fraud(s, config):
        return looked_up("fraud", "fraud", lambda: platform.get_fraud(s["request"]["customer"]), lk.Fraud,
                         lambda f: f"fraud score {f['score']}")

    def history(s, config):
        return looked_up("history", "history", lambda: platform.get_history(s["request"]["customer"]),
                         lk.History, lambda h: f"history: {h['refunds_30d']} refunds in 30 days, "
                                               f"{len(h['notes'])} notes")

    def screen(s, config):
        return {}                                   # code only: the route below decides

    def fraud_review(s, config):
        r, f = s["request"], s["fraud"]
        task = (f"Customer {r['customer']} asks for a refund on order {s['claim']['order_id']}. "
                f"Fraud score {f['score']}, signals: {', '.join(f['signals'])}. Review and give a verdict.")
        handoff, cost = charged(lambda: FRAUD_REVIEW.run(llm, platform, task, "refund_agent", tracer))
        return {"fraud_review": handoff["result"] or {"risk": "high", "evidence": ["review did not finish"]},
                "handoffs": [handoff], "spent": cost}

    def decide(s, config):
        feedback = "; ".join(s.get("problems") or []) or None
        claim = judgments.Classification(**s["claim"])
        try:
            d, cost = charged(lambda: judgments.decide(llm, s["request"]["message"], claim, s["order"],
                                                       s["policy"], s["fraud"], feedback,
                                                       s.get("history"), s.get("fraud_review")))
        except ValidationError as e:                 # the model's JSON didn't fit the schema
            return {"decision": None, "attempts": 1,
                    "problems": [f"your answer was not valid JSON for the schema: {str(e).splitlines()[0]}"]}
        return {"decision": d.model_dump(), "spent": cost, "attempts": 1, "problems": []}

    def verify(s, config):
        if s.get("decision") is None:
            return {"problems": s.get("problems") or ["no decision"]}
        return {"problems": check(judgments.Decision(**s["decision"]), s["order"], s["policy"], s["fraud"],
                                  s.get("history"), s.get("fraud_review"))}

    def ask_manager(s, config):
        d = s["decision"]
        return {"approval_request": platform.request_approval(
            config["configurable"]["thread_id"], s["order"]["order_id"], d["amount"], d["reason"])}

    def approval(s, config):
        answer = interrupt({"approval_id": s["approval_request"]["id"],
                            "question": f"Refund ${s['decision']['amount']:g}? ({s['decision']['reason']})"})
        return {"approval": answer}

    def refund(s, config):
        # One refund per order (stage 07): two runs for the same order at the same moment both
        # read a history with no refund in it; a key per run would let both pay.
        key = f"{s['order']['order_id']}:refund"
        return {"payment": platform.pay(s["order"]["order_id"], s["decision"]["amount"], idempotency_key=key)}

    def stream_reply(s, config):
        """Stage 04: write the reply while the customer watches it appear."""
        sid, seq = session_of(s, config), iter(range(10_000))
        before = llm.usage.cost
        out = judgments.compose(llm, s["request"]["message"], s["decision"],
                                lambda piece: platform.push_chunk(sid, run_id(config), next(seq), piece))
        return out, llm.usage.cost - before

    def reply(s, config):
        d, spent, streamed = s["decision"], 0.0, None
        if s.get("approval") == "rejected":
            text = "We reviewed your request and can't refund this order. A colleague will follow up."
        elif s.get("payment", {}).get("replayed"):
            text = ("This order has already been refunded, so there's nothing more to send. "
                    "The refund reaches your card in 5 to 10 working days.")
        else:
            streamed, spent = stream_reply(s, config)
            text = streamed["text"] or d["customer_message"]
        note = f"{d['action']} ${d['amount']:g} under {d['clause']}: {d['reason']}"
        if s.get("approval") == "rejected":
            note = f"manager rejected a ${d['amount']:g} refund"
        if s.get("payment", {}).get("replayed"):
            note = f"duplicate request: order already refunded (${d['amount']:g}), no second payment"
        if streamed and streamed["aborted"]:
            note += " (the customer left before the reply finished)"
        if any(e["verdict"] == "flagged" for e in s.get("guardrails", [])):
            note += " (prompt injection attempt flagged)"
        platform.add_note(s["request"]["customer"], run_id(config), s["order"]["order_id"], note)
        out = say(s, config, text)
        checks = []
        if streamed:
            out["stream"] = {k: streamed[k] for k in ("ttft", "seconds", "chunks", "aborted", "model")}
            checks = gr.check_output(text, d)              # after sending: a stream can't be unsent
            if any(c["verdict"] == "flagged" for c in checks):
                out["correction"] = say(s, config, gr.correction(d))["text"]
                tracer.log(f"guardrail: reply corrected: {[c['evidence'] for c in checks]}")
        return {"reply": out, "spent": spent, "guardrails": checks}

    def support(s, config):
        # The hybrid: open-ended work, so a small agent loop runs *inside* this one node.
        out = support_agent(llm, platform, s["request"], tracer)
        platform.add_turn(session_of(s, config), s["request"]["customer"], "agent", out["text"], run_id(config))
        return {"reply": out}

    def escalate(s, config):
        failures = s.get("failures") or []
        if failures:
            text = lk.failure_message(failures, s.get("claim", {}).get("order_id"))
            why = [f"{f['service']}: {f['kind']} after {f['attempts']} attempts" for f in failures]
        else:
            text = "Thanks for your patience. A colleague will look at this and get back to you today."
            why = s.get("problems") or "over budget"
        return {"reply": say(s, config, text) | {"queue": "support-escalations", "why": why}}

    g = StateGraph(RefundState)
    for name, fn in [("session", session), ("guard", guard), ("classify", classify), ("explain", explain), ("screen", screen),
                     ("fraud_review", fraud_review), ("decide", decide), ("verify", verify),
                     ("ask_manager", ask_manager), ("approval", approval), ("refund", refund),
                     ("reply", reply), ("support", support), ("escalate", escalate)]:
        g.add_node(name, traced(name, fn))
    for name, fn in [("order", order), ("policy", policy), ("fraud", fraud), ("history", history)]:
        g.add_node(name, traced(name, fn))           # retries live in lookups.fetch (stage 05)

    g.add_edge(START, "session")
    g.add_edge("session", "guard")
    g.add_edge("guard", "classify")
    g.add_conditional_edges("classify", route_after_classify, LOOKUPS + ["explain", "support"])
    g.add_edge(LOOKUPS, "screen")
    g.add_conditional_edges("screen", route_after_lookups, ["escalate", "fraud_review", "decide"])
    g.add_edge("fraud_review", "decide")
    g.add_edge("decide", "verify")
    g.add_conditional_edges("verify", route_after_verify,
                            ["decide", "escalate", "ask_manager", "refund", "reply"])
    g.add_edge("ask_manager", "approval")
    g.add_conditional_edges("approval", lambda s: "refund" if s["approval"] == "approved" else "reply",
                            ["refund", "reply"])
    g.add_edge("refund", "reply")
    for done in ("reply", "support", "escalate", "explain"):
        g.add_edge(done, END)

    db.parent.mkdir(parents=True, exist_ok=True)
    return g.compile(checkpointer=SqliteSaver(sqlite3.connect(db, check_same_thread=False)))


def route_after_lookups(s):
    if s.get("failures"):
        return "escalate"                 # never decide on missing facts (stage 05)
    return "fraud_review" if grey_zone(s["fraud"]) else "decide"


def grey_zone(fraud):
    """§9: neither clearly fine nor clearly fraud, so the fraud-review sub-agent decides."""
    return 0.4 <= fraud["score"] <= 0.7


def route_after_classify(s):
    kind = s["claim"]["kind"]
    if kind == "follow_up" and s["session"]["turns"]:
        return "explain"
    if kind == "refund_request" and s["claim"].get("order_id"):
        return LOOKUPS
    return "support"


def route_after_verify(s):
    if s.get("budget") is not None and s.get("spent", 0) > s["budget"]:
        return "escalate"
    if s.get("problems"):
        return "decide" if s.get("attempts", 0) < MAX_ATTEMPTS else "escalate"
    d = s["decision"]
    if d["action"] != "refund":
        return "reply"
    return "ask_manager" if needs_manager(s) else "refund"


def needs_manager(s):
    """§3 and §8 are code: the amount, or a customer who claims often."""
    frequent = s.get("history", {}).get("refunds_30d", 0) >= FREQUENT_CLAIMS
    return s["decision"]["amount"] > APPROVAL_LIMIT or frequent


def spec(graph):
    """Nodes and edges for the live viewer, read from LangGraph's own description of the graph."""
    drawable = graph.get_graph()
    nodes = [n for n in drawable.nodes if not n.startswith("__")]
    kinds = {"session": "http · memory", "guard": "guardrail · rules, model if unsure", "explain": "model · calls policy_expert", "classify": "model",
             "screen": "code", "fraud_review": "sub-agent", "decide": "model", "support": "model · loop inside",
             "approval": "person", "refund": "http · money", "order": "http", "policy": "http",
             "fraud": "http", "history": "http · memory", "ask_manager": "http", "reply": "http"}
    edges = [{"from": e.source, "to": e.target, "cond": e.conditional}
             for e in drawable.edges if not e.source.startswith("__") and not e.target.startswith("__")]
    return {"entry": "session", "nodes": [{"id": n, "kind": kinds.get(n, "code")} for n in nodes],
            "edges": edges}
