#!/usr/bin/env python3
"""Tests. Run: python test_memgate.py"""
import sys
from memgate import (build_dataset, MemGatePolicy, SlidingWindowPolicy,
                     FullContextPolicy, run_policy)
from memgate.scoring import HeuristicScorer
from memgate.store import ThreeTierStore
from memgate.types import MemoryItem, SHORT_TERM
from memgate.utils import count_tokens, embed, cosine

passed = failed = 0


def check(name, cond, detail=""):
    global passed, failed
    if cond:
        passed += 1
        print(f"  PASS  {name}")
    else:
        failed += 1
        print(f"  FAIL  {name}  {detail}")


print("\n-- utils --")
from memgate.utils import backend_info
print(f"  backends: {backend_info()}")
check("tokenizer non-zero", count_tokens("hello world") > 0)
check("tokenizer empty", count_tokens("") == 0)


def _same_vec(a, b):
    """Backend-agnostic equality: the embedder returns numpy arrays when numpy
    is present and plain lists otherwise."""
    return len(a) == len(b) and all(abs(x - y) < 1e-6 for x, y in zip(a, b))


check("embedding deterministic", _same_vec(embed("the deadline is March 15"),
                                           embed("the deadline is March 15")))
check("cosine self ~ 1", abs(cosine(embed("abc def"), embed("abc def")) - 1.0) < 1e-6)
check("embedding is normalised",
      abs(cosine(embed("a longer sentence here"),
                 embed("a longer sentence here")) - 1.0) < 1e-6)
check("cosine separates unrelated text",
      cosine(embed("budget 40000 rupees"), embed("hello there friend")) < 0.9)

print("\n-- scorer --")
s = HeuristicScorer()
check("filler scores low", s.score("ok thanks")[0] < 0.1)
check("greeting scores low", s.score("hey")[0] < 0.1)
check("fact scores high", s.score("The deadline is March 15.")[0] > 0.45)
check("budget fact scores high", s.score("My budget is 40000 rupees.")[0] > 0.45)
check("fact labelled", s.score("My budget is 40000 rupees.")[1] == "fact")
check("chatter below fact threshold",
      s.score("That makes sense to me overall.")[0] < 0.45)
# The router scores the stored "[Speaker] message" string (policies._as_item),
# so the rules above must hold for that form too, not only for bare text.
_tagged = [("[user] ok thanks", "user"), ("[Caroline] I went to the market.", "Caroline"),
           ("[Maria] We decided to keep the old car.", "Maria"),
           ("[Maria] I went there on 7 May.", "Maria"),
           ("[assistant] Got it: report due 2 November.", "assistant")]
check("speaker tag does not change the score",
      all(s.score(t, sp) == s.score(t.split("] ", 1)[1], sp) for t, sp in _tagged))
check("tagged filler still scores low", s.score("[user] ok thanks", "user")[0] < 0.1)
check("capitalised speaker name is not a proper-noun signal",
      s.score("[Caroline] That makes sense to me overall.", "Caroline")[1] == "context")

print("\n-- store --")
st = ThreeTierStore(short_capacity=3)
ev = [st.add_short(MemoryItem(text=f"turn {i}", tier=SHORT_TERM, kind="turn",
                              session=0, turn_index=i)) for i in range(5)]
check("buffer respects capacity", len(st.short) == 3)
check("evicts oldest first", ev[3] is not None and ev[3].text == "turn 0")
check("no eviction while under capacity", ev[0] is None and ev[2] is None)

st2 = ThreeTierStore()
src = MemoryItem(text="x", tier=SHORT_TERM, kind="turn", session=0, turn_index=0)
st2.add_long("The deadline is March 15.", src)
st2.add_long("The deadline is March 15.", src)      # exact duplicate
check("dedupe blocks duplicate", len(st2.long) == 1, f"got {len(st2.long)}")
st2.add_long("Ravi joined as a developer.", src)
check("distinct fact stored", len(st2.long) == 2, f"got {len(st2.long)}")

print("\n-- dataset integrity --")
turns, questions = build_dataset(n_sessions=8, turns_per_session=20, n_facts=16)
stmts = [t.text for t in turns if t.fact_id]
check("facts planted", len(stmts) > 0)
check("probes unique", len({q.text for q in questions}) == len(questions))
check("every probe is planted",
      {q.gold_fact_id for q in questions} <= {t.fact_id for t in turns if t.fact_id})

print("\n-- budget discipline --")
turns, questions = build_dataset()
for budget in (100, 400, 1200):
    p = MemGatePolicy()
    for t in turns:
        p.observe(t)
    ctx = p.build_context(questions[0].text, budget)
    check(f"MemGate respects budget {budget}", ctx.tokens <= budget,
          f"used {ctx.tokens}")

    p0 = SlidingWindowPolicy()
    for t in turns:
        p0.observe(t)
    c0 = p0.build_context(questions[0].text, budget)
    check(f"P0 respects budget {budget}", c0.tokens <= budget, f"used {c0.tokens}")

print("\n-- end-to-end behaviour --")
r_full = run_policy(FullContextPolicy(), turns, questions, 10**9)
r_mg = run_policy(MemGatePolicy(), turns, questions, 800)
r_p0 = run_policy(SlidingWindowPolicy(), turns, questions, 800)
check("full-context recalls everything", r_full["recall"] == 1.0)
check("MemGate beats sliding window at equal budget",
      r_mg["recall"] > r_p0["recall"], f"{r_mg['recall']} vs {r_p0['recall']}")
check("MemGate far cheaper than full-context",
      r_mg["avg_tokens"] < r_full["avg_tokens"] / 3)
# Leak-free baseline. This was 0.8 when consolidation promoted on the
# ground-truth fact_id; the honest P1 number at this budget is ~0.50, and the
# write path (only ~half the planted facts clear tau_fact) is the ceiling.
# Raise this as the scorer improves -- do not relax it.
check("MemGate recall clears leak-free baseline",
      r_mg["recall"] >= 0.45, f"{r_mg['recall']}")

print("\n-- compressor keeps content, not the greeting --")
from memgate.compress import compress
_dlg = "[Caroline] Hey Mel! Good to see you! How have you been? I finally " \
       "signed up for the LGBTQ support group on 7 May 2023."
_c = compress(_dlg, 14)
check("compression respects the token budget", count_tokens(_c) <= 14,
      f"{count_tokens(_c)} tokens: {_c!r}")
# The whole point: head-truncation would keep "Hey Mel! Good to see you! How"
# and lose the date, which IS the answer to "when did Caroline go...".
check("keeps the date over the greeting", "2023" in _c, _c)
check("drops phatic filler", "Hey" not in _c, _c)
check("keeps the speaker tag", _c.startswith("[Caroline]"), _c)

_fact = "[user] My budget for the analytics dashboard is 40000 rupees."
_cf = compress(_fact, 12)
check("keeps numbers and entities",
      "40000" in _cf and "analytics" in _cf, _cf)
check("short text passes through untouched",
      compress("[user] Deadline is March 15.", 99) == "[user] Deadline is March 15.")
check("compression preserves word order",
      [w for w in _cf.split() if w in _fact.split()] ==
      [w for w in _fact.split() if w in _cf.split()], _cf)

print("\n-- consolidation re-summarises rather than discards --")
# Tier 2 used to be a death chamber: routing only sends items scoring below
# tau_fact (0.45) there, but survival required clearing promote_threshold (0.5),
# so nothing could ever get out. Consolidation now merges the remainder into
# coarser gists instead of dropping them.
_ct, _cq = build_dataset(n_sessions=10, turns_per_session=40, n_facts=20)
_cp = MemGatePolicy(budget=2048)
for t in _ct:
    _cp.observe(t)
_merged = [i for i in _cp.store.working if i.fragments]
check("consolidation produced merged gists", _cp.store.merges > 0,
      f"merges={_cp.store.merges}")
check("merged gists survive in tier 2", len(_merged) > 0)

# The honest-accounting invariant. A merged gist may only claim evidence ids
# whose TEXT it still physically contains -- recursive merging otherwise
# accumulates ids while truncating the text away, and one item ended up
# claiming 373 turns in 221 tokens, reporting a write-path ceiling it could not
# support. A fragment is kept whole with its ids, or dropped with them.
_bad = [i for i in _merged
        if set(i.covered_ids) != {x for ids, _ in i.fragments for x in ids}]
check("merged gist claims only ids it still holds text for", not _bad,
      f"{len(_bad)} items claim ids with no surviving fragment")

# and every fragment's text must actually be in the item's text
_lost = [i for i in _merged if any(t not in i.text for _, t in i.fragments)]
check("every claimed fragment is present in the text", not _lost,
      f"{len(_lost)} items lost fragment text")

# granularity: merging must not collapse tier 2 into one atomic block, which
# either fits the tier-2 share whole or is skipped whole (cost -1.2 pts @2048)
_toks = [count_tokens(i.text) for i in _merged]
check("merged gists stay chunked, not one block",
      not _toks or max(_toks) <= _cp.store.chunk_tokens * 2,
      f"largest merged item is {max(_toks) if _toks else 0} tokens")

print("\n-- supersession --")
# Staleness handling: "Actually, we pushed the bakery module deadline to April 2"
# must retire the record it corrects, found by SEMANTIC match (the fact_id
# version was an oracle -- it was handed the record to invalidate).
_sup_turns, _ = build_dataset()
_upd = [t for t in _sup_turns if t.text.startswith("Actually,")]
check("dataset plants exactly one update", len(_upd) == 1, f"got {len(_upd)}")

_p = MemGatePolicy()
for t in _sup_turns:
    _p.observe(t)
_dead = [i for i in _p.store.long if not i.is_active]

# Invariant that must hold under ANY embedder: one update retires at most one
# record. Superseding every match above the bar once cascaded through the
# near-identical decision facts and cost ~10 recall points.
check("an update retires at most one record", len(_dead) <= 1,
      f"retired {len(_dead)}")

# Correctness depends on embedding quality, so it is asserted only where it is
# achievable. With hashing bag-of-words the nearest competitor outranks the true
# target (0.583 vs 0.500), so the ranking is inverted and this cannot pass --
# which is precisely the point of keeping the ablation.
_is_minilm = backend_info()["embedder"].startswith("all-MiniLM")
if _is_minilm:
    check("supersession retires the CORRECT record",
          len(_dead) == 1 and _dead[0].fact_id == _upd[0].fact_id,
          f"retired {[d.fact_id for d in _dead]}, expected {_upd[0].fact_id}")
else:
    print("  SKIP  supersession correctness (needs MiniLM; hashing inverts the "
          "ranking, 0.583 competitor vs 0.500 true target)")

print("\n-- no ground-truth leakage --")
# `fact_id` and `is_filler` are EVALUATION LABELS (types.py). If any routing,
# promotion, dedupe or supersession decision reads one, the reported recall is
# partly the answer key rather than the policy. Pin it: strip the labels and the
# store must come out bit-identical.
#
# This is not hypothetical. Promotion on `it.fact_id` in consolidation was worth
# +45 to +47.5 points here before it was removed.
from memgate.types import Turn


def _tier_fingerprint(ts, **kw):
    p = MemGatePolicy(**kw)
    for t in ts:
        p.observe(t)
    return ([i.text for i in p.store.short],
            [i.text for i in p.store.working],
            [(i.text, i.is_active) for i in p.store.long])


blind = [Turn(t.session, t.index, t.speaker, t.text) for t in turns]
check("routing is invariant to ground-truth labels",
      _tier_fingerprint(turns) == _tier_fingerprint(blind),
      "a policy decision is reading fact_id/is_filler")

# The storage budget added two more decision points that could read the answer
# key -- which item to EVICT and which to DEMOTE -- so the same invariant has to
# hold with the cap engaged, in both write modes. Eviction ranks on `utility`
# and recency only (store._forget_key).
for _mode in ("threshold", "adaptive"):
    check(f"eviction under a storage budget is label-blind ({_mode})",
          _tier_fingerprint(turns, store_budget=600, write_mode=_mode)
          == _tier_fingerprint(blind, store_budget=600, write_mode=_mode),
          "an eviction or demotion decision is reading fact_id/is_filler")


# A summariser decides WHAT TEXT SURVIVES compression, which is a policy
# decision of exactly the kind this section exists to constrain. Injected here
# as a deterministic stub rather than the real LLM: the property under test is
# label-blindness, not summary quality, and a stub keeps the suite offline,
# fast and reproducible.
def _stub_summariser(text, max_words):
    return " ".join(text.split()[:max_words])


for _mode in ("threshold", "adaptive"):
    check(f"an injected summariser is label-blind ({_mode})",
          _tier_fingerprint(turns, store_budget=600, write_mode=_mode,
                            summariser=_stub_summariser)
          == _tier_fingerprint(blind, store_budget=600, write_mode=_mode,
                               summariser=_stub_summariser),
          "the summariser path is reading fact_id/is_filler")

# The abstractive experiment routed three call sites -- demotion under pressure
# and both merge paths -- through ThreeTierStore._gist. With no summariser
# injected that indirection must be BYTE-IDENTICAL to the extractive rule those
# sites called directly, or every number from §23 onward moves silently and the
# swap stops being a single-component comparison.
from memgate.store import ThreeTierStore as _TTS
from memgate.compress import informative_head as _ih

_gist_samples = [t.text for t in turns[:20]] + [
    "[Caroline] Hey Mel! Good to see you! My sister Priya moved to Pune in March."]
check("the _gist hook is a no-op without a summariser",
      all(_TTS()._gist(s, 8) == _ih(s, 8) for s in _gist_samples),
      "routing compression through _gist changed the extractive output")
check("head-truncation ablation still reachable through _gist",
      all(_TTS(informative_compress=False)._gist(s, 8)
          == " ".join(s.split()[:8]) for s in _gist_samples),
      "the informative_compress=False ablation no longer head-truncates")

# P4 learns DURING the run, so the scorer is state that evolves with the
# conversation -- a new decision point, and one whose feedback arrives from item
# text alone. Same invariant, and it matters more here than anywhere: a scorer
# that could see labels would be learning the answer key rather than the user.
from memgate.online import OnlineScorer as _OS

check("online scorer is label-blind at inference",
      _tier_fingerprint(turns, scorer=_OS(), store_budget=600,
                        write_mode="adaptive")
      == _tier_fingerprint(blind, scorer=_OS(), store_budget=600,
                           write_mode="adaptive"),
      "the online scorer path is reading fact_id/is_filler")

_online = _OS()
_before, _ = _online.score("We moved the bakery deadline to April 2.")
_online.feedback(["[A] The deadline for the bakery app is April 2."],
                 ["[B] ok", "[B] thanks", "[B] sounds good"])
_after, _lab = _online.score("We moved the bakery deadline to April 2.")
check("online feedback updates the scorer and stays bounded",
      _online.stats()["updates"] > 0 and 0.0 <= _after <= 1.0
      and isinstance(_lab, str),
      "retrieval feedback did not update, or the utility left [0,1]")
check("online scorer starts at the heuristic prior",
      abs(_before - HeuristicScorer().score(
          "We moved the bakery deadline to April 2.")[0]) < 1e-9,
      "a cold online scorer must be exactly P1, or the warm-up is measured "
      "as a regression")

print("\n-- storage budget --")
# §22.3: the experiment capped the CONTEXT but never the STORE, so "keep
# everything and retrieve" was charged nothing for holding the whole
# conversation and forgetting could only ever lose. These pin the cap itself.
from memgate.policies import (SlidingWindowPolicy, RAGPolicy,
                              MemGateAdaptivePolicy)

for _name, _F in [("P0", SlidingWindowPolicy), ("RAG", RAGPolicy),
                  ("P1", MemGatePolicy), ("P1-A", MemGateAdaptivePolicy)]:
    _worst = []
    for _S in (256, 512, 1024, 2048):
        _p = _F(budget=1024, store_budget=_S)
        for _t in turns:
            _p.observe(_t)
        _worst.append((_S, _p.stored_tokens()))
    check(f"{_name} never exceeds its storage budget",
          all(v <= _S for _S, v in _worst),
          f"held more than allowed: {_worst}")

# A storage budget must actually BITE, or the sweep is measuring nothing. The
# unconstrained store holds the whole conversation; a capped one cannot.
_free = MemGateAdaptivePolicy(budget=1024, store_budget=None)
_tight = MemGateAdaptivePolicy(budget=1024, store_budget=512)
for _t in turns:
    _free.observe(_t)
    _tight.observe(_t)
check("a tight storage budget forces real loss",
      _tight.stored_tokens() < _free.stored_tokens(),
      f"tight={_tight.stored_tokens()} free={_free.stored_tokens()}")

# Sub-threshold items are dropped at ingest in threshold mode. With a storage
# budget that is waste while the store still has room, so `fill_store` keeps
# them instead and lets eviction decide later. It never fires on LoCoMo (whose
# turns all clear tau_low) but does on the synthetic set, so it is pinned here.
_drop = MemGatePolicy(budget=800, store_budget=1200, fill_store=None)
_fill = MemGatePolicy(budget=800, store_budget=1200, fill_store="long")
for _t in turns:
    _drop.observe(_t)
    _fill.observe(_t)
check("fill_store keeps sub-threshold turns while the store has room",
      _fill.routed["filled"] > 0 and _drop.routed["dropped"] > 0
      and _fill.stored_tokens() > _drop.stored_tokens(),
      f"fill={_fill.routed} {_fill.stored_tokens()} "
      f"drop={_drop.routed} {_drop.stored_tokens()}")

# Adaptive mode's whole claim is that the compression RATE follows storage
# pressure. With room to spare nothing should be demoted at all.
check("adaptive mode compresses nothing when storage is free",
      _free.store.stats()["demoted"] == 0,
      f"demoted {_free.store.stats()['demoted']} with an unbounded store")
check("adaptive mode compresses under pressure",
      _tight.store.stats()["demoted"] > 0,
      "storage pressure did not trigger any demotion")

print("\n-- learned scorer --")
# P3-learned replaces P1's hand-chosen weights with a fitted model. It is
# trained on OTHER conversations' evidence labels, but at inference it must see
# text and speaker only -- otherwise it is the §13 leak with extra steps. The
# invariance test therefore has to cover this scorer too, not just P1.
try:
    import numpy as _np
    from sklearn.linear_model import LogisticRegression as _LR
    from memgate.scoring import LearnedScorer, features as _feat
    from memgate.utils import embed as _emb

    _X = _np.array([_feat(t.text, t.speaker) for t in turns], dtype=float)
    _y = _np.array([1 if t.fact_id else 0 for t in turns])
    _m = _LR(max_iter=1000, class_weight="balanced").fit(_X, _y)
    _sc = LearnedScorer(model=_m, use_embedding=False)

    check("learned scorer is label-blind at inference",
          _tier_fingerprint(turns, scorer=_sc, store_budget=600,
                            write_mode="adaptive")
          == _tier_fingerprint(blind, scorer=_sc, store_budget=600,
                               write_mode="adaptive"),
          "the learned scorer path is reading fact_id/is_filler")

    _a, _l = _sc.score("We moved the bakery deadline to April 2.")
    check("learned scorer returns a bounded utility and a label",
          0.0 <= _a <= 1.0 and isinstance(_l, str))
except ImportError:
    print("  SKIP  sklearn not installed")

print("\n-- REALTALK evidence and the scorer's input string --")
from memgate.data import _realtalk_evidence
check("REALTALK evidence ranges, separators and dots normalise",
      _realtalk_evidence(["D12:3-D12:5", "D11:17; D16:1", "D5:3.", "D13:4. D14:4"])
      == ["D12:3", "D12:4", "D12:5", "D11:17", "D16:1", "D5:3", "D13:4", "D14:4"])
check("an unparseable REALTALK id is kept so the question is dropped",
      _realtalk_evidence(["D13:45:D20:19"]) == ["D13:45:D20:19"])
from train_transfer import MessageOnly
_h = HeuristicScorer()
check("MessageOnly scores the message, not the [speaker] tag",
      MessageOnly(_h).score("[Maria] ok thanks", "Maria")
      == _h.score("ok thanks", "Maria"))
check("P1 itself now ignores the [speaker] tag",
      _h.score("[Maria] ok thanks", "Maria") == _h.score("ok thanks", "Maria"))

print("\n-- shipped learned scorer (MEMGATE_SCORER) --")
import os as _os2
from memgate.pretrained import load_learned, default_scorer
check("the library default stays P1 when MEMGATE_SCORER is unset",
      _os2.environ.get("MEMGATE_SCORER") is not None
      or isinstance(default_scorer(), HeuristicScorer))
_shipped = load_learned()
if _shipped is None:
    print("  SKIP  shipped scorer not loadable here (needs MiniLM)")
else:
    _hi = _shipped.score("[Caroline] I start my new job at the hospital on 3 March.")[0]
    _lo = _shipped.score("[Melanie] haha yeah totally")[0]
    check("shipped scorer ranks a dated plan above chit-chat", _hi > _lo,
          f"{_hi:.3f} vs {_lo:.3f}")
    check("shipped scorer is label-blind at inference",
          _tier_fingerprint(turns, scorer=_shipped, store_budget=600,
                            write_mode="adaptive")
          == _tier_fingerprint(blind, scorer=_shipped, store_budget=600,
                               write_mode="adaptive"))

print("\n-- BEAM evidence ids --")
from memgate.data import _beam_ids
check("BEAM evidence lists flatten as given",
      _beam_ids([28, [3, 4]]) == [28, 3, 4])
check("BEAM two-sided evidence keeps both sides",
      _beam_ids({"original_info": [86], "updated_info": [114]}) == [86, 114])

from memgate.data import _beam_segments, _resolve_segment, _beam_chat
_t = lambda i, txt="x": {"id": i, "role": "user", "content": txt}
_chat = [{"turns": [[_t(0), _t(1)], [_t(2, "my flight is on 14 December")]]},
         {"turns": [[_t(0), _t(1, "the budget is 85000 rupees")]]}]
_segs = _beam_segments(_chat)
check("BEAM 1M: ids that restart begin a new segment",
      [[t["id"] for s in seg for t in s] for seg in _segs] == [[0, 1, 2], [0, 1]])
_txt = [{t["id"]: t["content"] for s in seg for t in s} for seg in _segs]
check("BEAM: a repeated id is pinned to the segment whose words match",
      _resolve_segment([1], _txt, ["budget", "85000"]) == 1)
check("BEAM: an id only one segment holds needs no words",
      _resolve_segment([2], _txt, []) == 0)
check("BEAM: a repeated id with no matching words is dropped, not guessed",
      _resolve_segment([0], _txt, ["budget"]) is None)
_cnt = {"dangling": 0, "empty": 0, "ambiguous": 0}
_ts, _qs = _beam_chat("b", _segs, {"information_extraction": [
    {"question": "What is my budget?", "answer": "85000 rupees", "source_chat_ids": [1]},
    {"question": "Which id?", "answer": "x", "source_chat_ids": [0]}]}, _cnt)
check("BEAM: segmented turn ids are unique and evidence points at the right copy",
      len({t.fact_id for t in _ts}) == 5 and _qs[0].evidence_ids == ["b/1:1"]
      and _cnt["ambiguous"] == 1)
_ts1, _ = _beam_chat("b", _segs[:1], {}, _cnt)
check("BEAM 100K/500K (one segment) keep their old ids",
      [t.fact_id for t in _ts1] == ["b/0", "b/1", "b/2"])

print("\n-- MemBench --")
import json as _json, tempfile as _tf
from memgate.data import load_membench
with _tf.TemporaryDirectory() as _d:
    _os_ = __import__("os")
    _os_.makedirs(_os_.path.join(_d, "FirstAgent"))
    _os_.makedirs(_os_.path.join(_d, "ThirdAgent"))
    _step = lambda i, u: {"sid": i, "user_message": u, "assistant_message": "nice!"}
    with open(_os_.path.join(_d, "FirstAgent", "simple.json"), "w") as _f:
        _json.dump({"roles": {}, "events": [{"tid": 0, "message_list": [
            [_step(0, "hi"), _step(1, "My uncle lives in Portland, OR.")],
            [_step(2, "he likes hiking")]],
            "QA": {"question": "Where does my uncle live?", "answer": "Portland, OR",
                   "target_step_id": [[1, 0]], "choices": {"A": "Portland, OR"},
                   "ground_truth": "A"}}]}, _f)
    with open(_os_.path.join(_d, "ThirdAgent", "simple.json"), "w") as _f:
        _json.dump({"events": [{"tid": 3, "message_list": [
            {"mid": 0, "message": "Team Connect is in Boston, MA."}],
            "QA": {"question": "Where?", "answer": "Boston, MA", "target_step_id": [0],
                   "choices": {"C": "Boston, MA"}, "ground_truth": "C"}}]}, _f)
    _mb = load_membench(_d)
_s1, _t1, _q1 = _mb[0]
check("MemBench FirstAgent: a step is a user turn then an assistant turn",
      [t.speaker for t in _t1] == ["user", "assistant"] * 3
      and [t.session for t in _t1] == [0, 0, 0, 0, 1, 1]
      and [t.index for t in _t1] == [0, 1, 2, 3, 0, 1])
check("MemBench FirstAgent: evidence is the user's message of the cited step",
      _q1[0].evidence_ids == [f"{_s1}/1u"] and _q1[0].answer_recoverable)
check("MemBench ThirdAgent: evidence is the cited message",
      _mb[1][2][0].evidence_ids == [f"{_mb[1][0]}/0"] and _mb[1][2][0].answer == "Boston, MA")

print("\n-- PersonaChat --")
from memgate.data import load_personachat, _states
check("PersonaChat: a turn states a persona line when it says most of its words",
      _states("i like to go hunting .", "hunting is one of my favorite hobbies .")
      and not _states("i like to remodel homes .", "i like to go out a lot ."))
with _tf.TemporaryDirectory() as _d:
    _fn = __import__("os").path.join(_d, "pc.json")
    with open(_fn, "w") as _f:
        _json.dump({"train": [{"personality": ["i have two dogs .", "i love iced tea ."],
                               "utterances": [{"history": ["hi , what do you do ?",
                                                           "i walk my two dogs a lot .",
                                                           "nice ! i read ."],
                                               "candidates": ["x", "cool , i read too ."]}]}]},
                   _f)
    _pc = load_personachat(_fn, per_unit=20)
_s, _t, _q = _pc[0]
check("PersonaChat: the persona speaker is the user, the partner the assistant",
      [t.speaker for t in _t] == ["assistant", "user", "assistant", "user"])
check("PersonaChat: only stated lines become questions, with the turn as evidence",
      len(_q) == 1 and _q[0].evidence_ids == [f"{_s}/0:1"] and _q[0].answer == "dogs two")

print("\n-- offline reproducibility --")
# A run that can silently fetch a model is a run whose inputs are not pinned,
# and this project has already lost a results table to a half-downloaded
# MiniLM (§16.3). Two things must hold: importing the package pins the loaders
# offline, and the embedder still resolves to MiniLM once it is pinned. The
# second is the one that matters -- if offline mode made MiniLM unloadable the
# fallback would quietly relabel every result as hashing bag-of-words.
import os as _os
from memgate.utils import backend_info as _bi
check("import pins the HF loaders offline",
      _os.environ.get("HF_HUB_OFFLINE") == "1",
      "set MEMGATE_ALLOW_HUB=1 only when deliberately adding a model")
check("MiniLM still resolves with the Hub pinned off",
      _bi()["embedder"].startswith("all-MiniLM"),
      f"fell back to {_bi()['embedder']} -- results would be mislabelled")

print("\n-- reproducibility --")
a = run_policy(MemGatePolicy(), turns, questions, 800)
b = run_policy(MemGatePolicy(), turns, questions, 800)
check("runs are deterministic", a["recall"] == b["recall"] and
      a["avg_tokens"] == b["avg_tokens"])

print(f"\n{'='*46}\n  {passed} passed, {failed} failed\n{'='*46}")
sys.exit(1 if failed else 0)
