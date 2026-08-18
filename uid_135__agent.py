from __future__ import annotations

from harnyx_miner_sdk.decorators import entrypoint
from harnyx_miner_sdk.query import Query, Response


def _compose_zephyr_notary_entry():

    _S25_QUERY_TAG = "hk6717"

    import asyncio
    import json
    import re
    from time import monotonic

    from harnyx_miner_sdk.api import fetch_page, llm_chat, search_web, tooling_info
    from harnyx_miner_sdk.decorators import entrypoint
    from harnyx_miner_sdk.query import CitationRef, CitationSlice, Query, Response

    _CAP_PREMISE_TERMS = (
        "used to be", "former ", "formerly", "originally", "was known as",
        "renamed", "no longer", "used to have", "previously", "used to",
        "is it true that", "did ", "isn't ", "wasn't ",
    )
    _CAP_TIME_TERMS = (
        " as of ", "currently", "latest", "most recent", "which version",
        "effective date", "updated", "revision", "since when",
    )
    _CAP_CALC_TERMS = (
        "how many", "total", "difference", "percentage", "percent", "sum of",
        "average", "ratio", "combined", "product of", "divided by",
        "multiply", "how much more", "how much less",
    )
    _CAP_STRUCT_TERMS = (
        "json", "structured", "table with columns", "each field",
        "output format", "schema", "return the following fields",
        "list the fields",
    )
    _CAP_PREMISE_HINT = (
        "PREMISE CHECK: this question may embed a premise that is stale, "
        "misclassified, or no longer accurate. Verify every named fact "
        "(title, status, ownership, ranking, identity) against current "
        "authoritative evidence before answering; if the premise is "
        "false, state the correction explicitly with its citation, then "
        "answer the underlying intent -- do not merely note the premise "
        "is wrong and stop there."
    )
    _CAP_TIME_HINT = (
        "TIME/VERSION CHECK: credible sources may disagree only because "
        "they cover different effective dates, versions, populations, or "
        "jurisdictions. Name the scope each source covers and reconcile "
        "any apparent conflict explicitly -- state real residual "
        "uncertainty rather than silently picking one source."
    )
    _CAP_CALC_HINT = (
        "CALCULATION CHECK: recompute any reported figure yourself from "
        "the cited operands before finalizing -- state each operand with "
        "its own citation and the arithmetic step, not just the final "
        "number, so the calculation is independently verifiable."
    )
    _CAP_STRUCT_HINT = (
        "STRUCTURED-OUTPUT CHECK: if a structured shape is requested, "
        "every field's meaning, units, ordering, and date/version "
        "interpretation must exactly match what was asked -- never add a "
        "field that was not requested, and never leave one implicit."
    )
    _CAP_SIGNAL_TABLE = (
        (_CAP_PREMISE_TERMS, _CAP_PREMISE_HINT),
        (_CAP_TIME_TERMS, _CAP_TIME_HINT),
        (_CAP_CALC_TERMS, _CAP_CALC_HINT),
        (_CAP_STRUCT_TERMS, _CAP_STRUCT_HINT),
    )


    def _folded_contains_any(folded: str, terms: tuple[str, ...]) -> bool:
        return any(term in folded for term in terms)


    def _capability_signal_boost(question: str) -> str | None:
        q = (question or "").casefold()
        hints: list[str] = []
        for terms, hint in _CAP_SIGNAL_TABLE:
            if _folded_contains_any(q, terms):
                hints.append(hint)
        if not hints:
            return None
        return "\n\n".join(hints)


    VERSION = "hx62-405-uf1"

    LLM_LANE_A = "openrouter"
    LLM_LANE_B = "openrouter"
    LOOP_MODEL_A = "z-ai/glm-5.2"
    LOOP_MODEL_B = "z-ai/glm-5"
    AUDIT_MODEL = "openai/gpt-oss-120b"
    SCHEMA_MODEL = "openai/gpt-oss-120b"
    RESORT_MODEL = "deepseek/deepseek-v3.2"
    SEARCH_PROVIDER = "parallel"

    WALL_BUDGET_S = 266.0
    BRIEF_TIMEOUT_S = 50.0
    TURN_TIMEOUT_S = 75.0
    LANE_B_MAX_PAYLOAD_CHARS = 144000
    AUDIT_TIMEOUT_S = 28.0
    SEARCH_TIMEOUT_S = 18.0
    FETCH_TIMEOUT_S = 16.0
    WRAPUP_AT_S = 90.0
    MIN_TAIL_S = 8.0
    MAX_TURNS = 15
    AUDIT_EXTRA_TURNS = 2
    ANSWER_REPAIR_TURNS = 2
    RESCUE_TIMEOUT_S = 55.0
    DIGEST_TAIL_S = 14.0

    SEARCH_EXCERPT_CHARS = 550
    _LEDGER_TEXT_CAP = 400_000
    PAGE_GREP_WINDOW = 700
    PAGE_GREP_MAX_HITS = 6
    PAGE_READ_MAX_CHARS = 12_000

    RETAIN_MARGIN_CHARS = 260
    RETAIN_MAX_PER_ROW = 6
    RETAIN_MIN_QUOTE = 12
    FETCH_HEAD_CHARS = 3000
    FETCH_WINDOW_CHARS = 3600

    CITATION_MIN_SPAN_CHARS = 6000
    CITATION_MAX_REF_CHARS = 14_000
    FETCH_WINDOWS_PER_PAGE = 3
    FETCH_PLAIN_CHARS = 6500
    ANSWER_CHAR_CAP = 60000
    CITATION_CAP = 24
    EVIDENCE_CHAR_BUDGET = 105_000

    BRIEF_MIN_USD = 0.03
    AUDIT_MIN_USD = 0.05
    WRAPUP_MIN_USD = 0.02

    _TURN_TOOL_FANOUT = 8
    _BRIEF_REMAINING_FLOOR_S = 120.0
    _AUDIT_REMAINING_FLOOR_S = 75.0
    _FORMAT_REMAINING_FLOOR_S = 65.0
    _UNIT_REMAINING_FLOOR_S = 70.0
    _REPAIR_EXTRA_HEADROOM_S = 10.0
    _TOOL_PHASE_MIN_S = 5.0
    _TOOL_PHASE_PAD_S = 6.0
    _CHAT_TURN_FLOOR_S = 5.0
    _TOOL_SKIP_REPLY = (
        "# skipped: per-turn tool budget reached — re-issue next turn if still needed")
    _TOOL_TIMEOUT_REPLY = "# tool timed out — use what you already have"
    _TOOL_CRASH_PREFIX = "# tool crashed: "
    _EMPTY_QUESTION_TEXT = "No question provided."
    _UNAVAILABLE_PREFIX = "Best-effort answer unavailable for: "

    _SPEND = {"left": None}


    def _spend_note(payload) -> None:
        budget = getattr(payload, "budget", None)
        left = getattr(budget, "session_remaining_budget_usd", None)
        if isinstance(left, (int, float)):
            _SPEND["left"] = float(left)


    def _spend_left() -> float:
        left = _SPEND["left"]
        if isinstance(left, (int, float)):
            return float(left)
        return 1.0


    def _wall_remaining(deadline: float) -> float:
        return deadline - monotonic()


    def _empty_question_response() -> Response:
        return Response(text=_EMPTY_QUESTION_TEXT)


    def _unavailable_response(question: str, cap: int) -> Response:
        return Response(text=f"{_UNAVAILABLE_PREFIX}{question[:cap]}")


    LOOP_TOOLS = [
        {
            "type": "function",
            "function": {
                "name": "web_search",
                "description": ("Web search. Returns numbered results, each with title, "
                                "url and excerpt."),
                "parameters": {
                    "type": "object",
                    "properties": {"query": {"type": "string",
                                             "description": "the search query"}},
                    "required": ["query"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "sec_filing",
                "description": ("Resolve a company's SEC filing to its primary document "
                                "URL on sec.gov (exact form + year, from EDGAR's own "
                                "index). Use for questions about a specific filing "
                                "(10-K, 10-Q, 8-K, DEF 14A…), then read_page the "
                                "returned URL with a focus hint for the Item/section."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "company": {"type": "string",
                                    "description": "company name or ticker, e.g. 'Apple' or 'AAPL'"},
                        "form": {"type": "string",
                                 "description": "filing form, e.g. '10-K', '10-Q', '8-K', 'DEF 14A'"},
                        "year": {"type": "string",
                                 "description": "optional report (fiscal) year, e.g. '2019' (omit for latest)"},
                    },
                    "required": ["company", "form"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "read_page",
                "description": ("Fetch a URL and return its main text. Large pages show "
                                "the head plus the few regions most relevant to the "
                                "question; pass a focus hint to steer which regions."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string", "description": "URL to fetch"},
                        "focus": {"type": "string",
                                  "description": ("optional phrase to locate inside the "
                                                  "page (section name, table label, "
                                                  "entity)")},
                    },
                    "required": ["url"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "page_grep",
                "description": ("Search INSIDE a page you already fetched, by regex or "
                                "literal text, and get every match with its surrounding "
                                "context and character offset. Use this when read_page "
                                "showed you the head of a long page but the value you "
                                "need is deeper in it -- do not re-fetch, grep it."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string",
                                "description": "URL of a page already fetched this run"},
                        "pattern": {"type": "string",
                                    "description": ("regex or literal string to find, e.g. "
                                                    "a city name, a year, a column label")},
                    },
                    "required": ["url", "pattern"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "page_read",
                "description": ("Read an arbitrary character range of a page you already "
                                "fetched. Use the offsets page_grep reports to read the "
                                "full table or section around a match."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string", "description": "URL already fetched"},
                        "offset": {"type": "integer", "description": "start character offset"},
                        "length": {"type": "integer",
                                   "description": "how many characters to read (max 12000)"},
                    },
                    "required": ["url", "offset"],
                },
            },
        },
    {
            "type": "function",
            "function": {
                "name": "retain_evidence",
                "description": ("Keep the exact source text that proves a claim you are "
                                "about to make. Pass the result number and the verbatim "
                                "quote from it. Do this the moment you find a decisive "
                                "value -- the judge only credits claims whose citation "
                                "contains the supporting text, and this is how that text "
                                "gets into your citation. Use it for the QUESTION'S "
                                "PREMISES as well as your answer: every entity, work, "
                                "date or figure the question names should end up with a "
                                "retained quote confirming it."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "source": {"type": "string",
                                   "description": "result number to quote from, e.g. 3"},
                        "quote": {"type": "string",
                                  "description": ("verbatim text copied from that result "
                                                  "that states the fact")},
                    },
                    "required": ["source", "quote"],
                },
            },
        },
    ]

    LOOP_RULES = (
        "You are a research agent answering a hard multi-part factual question. A "
        "judge compares your answer head-to-head with a strong reference and only "
        "credits claims that carry a citation to a tool result that states them.\n\n"
        "PREFER THE PRIMARY SOURCE: when two sources state the same fact, cite the "
        "one that ORIGINATES it -- the agency, registry, filing, official statistics "
        "release or the organisation's own page -- not an encyclopedia or aggregator "
        "repeating it. Measured verbatim on a task where both answers were factually "
        "correct: \"Answer 1 is preferred for using primary sources\" (it cited NARA "
        "where we cited Wikipedia) -- a full point lost on every run. Use the "
        "encyclopedia to FIND the primary source, then fetch and cite that.\n\n"
        "QUOTE WHAT PROVES IT: the judge credits a claim only when your citation "
        "CONTAINS the source text stating it. The moment you read a decisive value, "
        "call retain_evidence(source, quote) with the exact words from that result. "
        "Do this for every condition you test and every figure you report -- an "
        "answer whose citations do not carry its numbers loses to one that does, "
        "even when both answers are identical.\n"
        "ALSO QUOTE THE QUESTION'S PREMISES, not only your answer. Every entity, "
        "work, date or figure the question NAMES is a claim the judge expects "
        "traceable: the film it says someone directed, the article it points at, "
        "the year it fixes, the people it lists. You lose to an otherwise identical "
        "answer that cited those too -- measured verbatim: \"does not provide a "
        "citation for 'Everyone Says I Love You'... Answer 1 is more thorough in "
        "its traceability to all parts of the prompt's context\". Retain a quote "
        "for each named premise as you confirm it, even when it is background you "
        "already believed.\n\n"
        "READ DEEP, DO NOT RE-FETCH: read_page shows the head plus a few regions of "
        "a long page. If the value you need is not in what you were shown, call "
        "page_grep(url, pattern) to find it anywhere in that page and page_read to "
        "open the region around a reported offset. Grepping a page you already have "
        "costs nothing and beats another search.\n\n"
        "METHOD: think in constraints and candidates. Recall what you already know "
        "to form the candidate pool, then use web_search/read_page to verify every "
        "load-bearing fact (names, figures, dates, rankings) before asserting it. "
        "Work every candidate through every stated condition; one search per fact "
        "beats one broad search. TWO DISTINCT SUB-QUESTIONS: if the question asks two "
        "separate things, answer BOTH substantively — a partial answer covering both "
        "sides outscores a complete answer to only one. BATCH YOUR LOOKUPS: independent facts (each "
        "candidate's score, each entity's figure) should be requested as SEVERAL "
        "tool calls in the SAME turn — they run in parallel, so a 6-candidate "
        "sweep costs one turn, not six. TABLE CARE: when reading a table, respect its "
        "qualifier columns (Owned vs Leased, the exact year, the exact segment) — "
        "count or compare only rows matching EVERY stated qualifier, and quote the "
        "row values you used. For a named source (Box Office Mojo, a 10-K, "
        "Nielsen), fetch THAT page — for SEC filings, use the sec_filing tool to "
        "resolve the exact primary document from EDGAR's own index, then read_page "
        "it with a focus hint for the Item/section.\n\n"
        "CITE EVERYTHING: put [n] (the tool-result number) immediately after the "
        "SENTENCE carrying each claim — not pooled at the end of a paragraph. Every "
        "sentence asserting a number, date, proper noun or causal link needs its own "
        "[n], for the entities you rule OUT as well as those you include. An uncited "
        "specific reads as invented. Cite only results that actually state the claim, "
        "and prefer the most AUTHORITATIVE one that does: the official database/"
        "filing/statistics page over an aggregator, blog, or retrospective article. "
        "CITE THE HARD CONDITION, NOT JUST THE POOL: every stated condition needs "
        "evidence of its own, and the one hardest to verify is the one the grader "
        "checks. Citations that establish only the candidate pool leave the actual "
        "filter unsupported — a right answer whose decisive condition is uncited "
        "loses to a weaker answer that proves it.\n\n"
        "SOURCE CONFIDENCE: when the question NAMES a source you could not reach but "
        "other authoritative evidence establishes the same facts, state those facts "
        "plainly and confidently with their [n], and treat the other sources as "
        "corroboration. Do not open with, dwell on, or append a note that the named "
        "source was unavailable — reserve missing-source language for a FACT that is "
        "genuinely absent everywhere, never for a missing source LABEL.\n\n"
        "SELF-CONSISTENCY: before you finish, check that the opening names exactly "
        "the entities your own cited sentences support. If the body establishes a "
        "different answer than the opening claims, rewrite the opening to match the "
        "evidence — never leave a weaker fallback in the lead.\n\n"
        "ANSWER SHAPE: sentence one IS the answer — the exact entities/values/list "
        "asked for, in the requested format. Never open with 'Based on…', 'From my "
        "research…', 'I can provide a partial answer', or any preamble — start with "
        "the answer entities themselves. ANSWER THE ASKED KIND: if the question asks "
        "which SERIES, name the series (not the people in it); which FILM, the film "
        "(not its director); which COUNTRY, the country. "
        "THE POOL IS THE WHOLE NAMED CLASS, NOT THE SURVIVORS: build it from the "
        "broadest set the question ranges over — every member of that class, not the "
        "ones you already believe qualify — then apply the conditions one at a time and "
        "show who each one eliminates. Never pre-filter to the members that already "
        "pass and present those as the pool — an answer whose pool contains only "
        "qualifiers proves nothing about the sweep, which is how a correct answer "
        "still scores zero. List members that fail on the FIRST condition too. "
        "Then: the candidate pool, each condition applied, and ONE LINE PER POOL MEMBER — "
        "a line for every qualifier with its qualifying attribute cited, AND a line "
        "for every candidate you rule out with its cited failing condition. Never "
        "compress several rejects into one clause ('X, Y and Z never won [n]'): each "
        "rejected member gets its own line and its own [n], even when the pool runs "
        "to a dozen members. A batched exclusion reads as a pool you never checked. "
        "Two later instructions may relax this — one when time runs short, one "
        "when the pool is too large to list in full — and nothing else does. "
        "If you cannot settle a member's condition, KEEP it among the qualifiers — a "
        "wrongly-dropped qualifier costs as much as a wrong answer — and give its "
        "line the strongest fact you did verify. Never add a note about what you "
        "could not check. "
        "OUTPUT DIRECTIVES ARE LITERAL: obey formatting instructions mechanically. "
        "Decide first whether a phrase constrains the OUTPUT or selects the "
        "ENTITIES: 'list them without the word \"X\"' shapes what you print, so "
        "DELETE X from each name; 'whose title does not contain \"X\"' / 'titles "
        "without the word X' is a condition on the pool, so keep only members that "
        "lack it. When the phrase governs how to print an already-chosen set, the "
        "deletion reading applies — it is not a filter. 'in alphabetical/chronological order' means sort the final "
        "list; 'comma-separated' means join with commas; a requested count means "
        "emit the number. These govern the ANSWER LINE — give it in exactly the "
        "requested shape, then still add the proof section below it; the shape "
        "directive is never a reason to omit the proof. COPY SOURCE VALUES "
        "VERBATIM: when the question names a source, every name, label and value in "
        "the answer must be the exact string that source prints -- never add a "
        "familiar alternative in parentheses, never anglicise a transliteration. "
        "'Makkah' is the answer; 'Mecca (Makkah)' is a wrong answer. "
        "ONE EXCEPTION, and it is "
        "absolute: if the question says to output ONLY the answer (\'output only\', "
        "\'respond with only\', \'nothing else\', \'no explanation\'), emit the answer "
        "line as the BARE requested text — no [n] markers on it, nothing else on "
        "that line: a trailing [3] makes the text inexact and fails the "
        "instruction. Still write the PROOF section BELOW it carrying its [n] "
        "markers. Only the answer line is shipped, but the citations are "
        "harvested from the proof first, and an uncited answer scores zero. "
        "Obeying that "
        "instruction IS the task. When an ORDER is demanded, "
        "the ANSWER LINE itself must be sorted — not merely the table under it. "
        "Print the sort key beside each item (the year, figure or date you sorted "
        "on) and check every adjacent pair before you finish: one member out of "
        "sequence fails the whole answer even when the set is exactly right. "
        "COMPUTED ANSWERS: if the answer is a mean, total, rank or count derived "
        "from several figures, pull every input into one explicit list first, then "
        "compute — and show the arithmetic so the number is checkable. Never report "
        "a derived number you did not visibly compute from listed inputs. "
        "ROUNDED FIGURE = WRONG SOURCE: a decisive number that reads as rounded — "
        "trailing zeros where the measuring body publishes exact digits, "
        "'X.Y thousand/million', 'about'/'approximately', "
        "or a value lifted from a chart label — came from an aggregator that "
        "publishes summaries, not from the body that measured it. Do NOT commit it. "
        "Search again for the exact figure from the source the question NAMES (or "
        "the outlet that reports that source's own numbers) and answer with the full "
        "precision it publishes, digit for digit. Quote the rounded value only as "
        "corroboration after the exact one. This is a RETRIEVAL instruction, not a "
        "licence to withhold: once tool calls are closed, or if the named source "
        "itself publishes only the rounded value, commit the best figure you hold "
        "and never remark on its precision. "
        "EXACT VALUES ONLY: this governs HOW you report a figure; the rule above "
        "governs WHICH figure to go and fetch. Once you hold the right one, use the "
        "figures you READ in a tool result, verbatim — preserve notation exactly (58.58% and "
        "58.6% are different; 'p < 0.0001' and 'P < .001' must not be merged or "
        "called consistent). If one source gives a range and another a point value, "
        "give both and say whether the point falls inside the range. If a figure is "
        "reported in different units than the question asks, convert it and give the "
        "exact converted result, preserving units and any timezone label. Answer with "
        "the value from the exact source, date and scope the question NAMES — do not "
        "substitute a later or broader figure unless resolving a conflict requires "
        "it. Bind every claim to the exact actor, target, date-window and instrument "
        "the evidence ties together; never carry a statement about one party or "
        "period across to another. Never a remembered or approximate value "
        "('~$1.33B'), never rounded, never an adjacent year/quarter/metric. If a "
        "deciding figure is still unverified at writing time, prefer the tool-read "
        "value you have over a guess, and NEVER write '(verify)' or any uncertainty "
        "marker in the final answer — the final answer contains only committed "
        "prose.\n\n"
        "AMBIGUOUS METRIC? ANSWER BOTH READINGS. If the asked quantity has two "
        "defensible interpretations — one party's value or the combined value of "
        "both; one dimension of size or another; a narrow scope or a consolidated "
        "one — do NOT silently pick one. Name the ambiguity in "
        "one clause and give BOTH lists/values, each cited and labelled. A correct "
        "answer under the reading the grader did not use still scores as wrong.\n\n"
        "APPLY CONDITIONS LITERALLY: copy each candidate's exact value, then test "
        "the comparator as written — 'more than 25' is strictly >25 (25 fails); "
        "'between 2010 and 2019' includes both endpoints; convert a rate condition "
        "into a concrete integer test ('averaged more than 1 per year over 10 "
        "years' = 'more than 10 in total'); read edition/date boundaries literally. "
        "EXCLUDE ONLY ON PROOF: reject a candidate by naming the specific stated "
        "condition it fails, with the cited fact showing the failure — never "
        "because it looks weaker than your front-runner. If it is UNCERTAIN "
        "whether a candidate fails a condition, KEEP IT in the answer rather than "
        "dropping it on a guess: a wrongly-dropped qualifier costs exactly as much "
        "as a wrong answer. SAY NO MORE THAN THE CITATION: if the source says "
        "'brought to', do not write 'incarcerated'; if it gives a count of 12, do "
        "not write 11. Check every count and every verb against its citation.\n\n"
        "NEVER NARRATE YOUR EVIDENCE: no sentence about what your results do or "
        "do not contain ('the evidence does not specify…', 'would be needed to "
        "determine…'). Those phrasings lose. A substantive negative about the "
        "WORLD is different and is a real answer when true ('No member of the "
        "class satisfies every condition [n]'). If a datum truly cannot be "
        "verified, commit "
        "to the best-supported value you found and move on. ONE narrow exception: "
        "when the asked figure genuinely does not exist in any published form, you "
        "may state the REASONED IMPOSSIBILITY — name the specific dataset that "
        "would hold it and why it cannot yield the value — as a fact about the "
        "world, in the first line, alongside the closest cited facts. That is a "
        "committed answer; 'the evidence does not contain it' is not.\n\n"
        "FINISH: never mix tool calls and the final answer in one turn. When the "
        "constraints are verified (or best-effort covered), write the complete "
        "cited answer."
    )


    def _wrapup_order(seconds_left: float) -> str:
        return (
            f"TIME IS UP (~{int(seconds_left)}s left). No more tool calls. Write the "
            "complete final answer NOW from the numbered results above plus your "
            "knowledge: the FIRST words are the answer entities (no 'Based on…' "
            "preamble, no 'partial answer' framing, no '(verify)' markers), cite [n] "
            "on every claim, keep the required format. A cited partial answer "
            "scores; a refusal or a remark about insufficient evidence scores zero."
            + ("" if seconds_left >= 60 else
               " BREVITY OVERRIDE: too little time remains for a line per pool "
               "member. Lead with the answer entities, then give the qualifiers one "
               "cited line each and compress the rejects into a single cited line. "
               "A complete short answer beats a long one that never finishes.")
        )


    _SET_HINT_RE = re.compile(
        r"\b(?:list|name|identify|enumerate)\b[^?]{0,40}\b(?:all|every|each|the)\b"
        r"|\bhow many\b|\bwhich (?:movies|films|series|countries|companies|states|"
        r"cities|books|albums|artists|players|teams|species|languages|banks|"
        r"universities|agencies|models|products)\b",
        re.IGNORECASE)
    _SET_CONNECTIVE_RE = re.compile(r"\b(?:both|also|and (?:also|had|has|was|were)|as well as)\b",
                                    re.IGNORECASE)


    _PLURAL_HEAD_RE = re.compile(r"\b(?:which|what)\b(?:\s+\w+){0,2}?\s+([a-z]{3,}s)\b", re.IGNORECASE)
    _PLURAL_FALSE = frozenset(
        "was is has does its this thus across process business series species news "
        "status analysis basis less unless always perhaps".split())
    _ONE_WINNER_RE = re.compile(
        r"\b(?:highest|lowest|largest|smallest|most|least|greatest|fewest|longest|"
        r"shortest|first|last|best|worst|only|oldest|youngest|newest|biggest)\b",
        re.IGNORECASE)
    _EST_STOP = frozenset(
        "interest honest modest protest request suggest forest harvest invest "
        "manifest contest arrest digest earnest conquest tempest midwest northwest "
        "southwest unrest bequest behest attest molest ingest infest detest incest "
        "armrest backrest pretest headrest footrest".split())
    _EST_RE = re.compile(r"\b([a-z]{3,})est\b")


    def _has_superlative(text: str) -> bool:
        if _ONE_WINNER_RE.search(text or ""):
            return True
        for m in _EST_RE.finditer(text or ""):
            if m.group(0).lower() not in _EST_STOP:
                return True
        return False


    def _needs_superlative_proof(question: str) -> bool:
        q = " ".join((question or "").split())
        if not q:
            return False
        return _has_superlative(q) or bool(
            re.search(r"\b(?:most|least) (?:common|frequent|number|amount)\b|\bhow many\b", q, re.I))


    SUPERLATIVE_RULE = (
        "SUPERLATIVE / TALLY — SHOW THE TABLE. The answer is one item, but you "
        "cannot know it without the whole pool. Before naming a winner: (1) list "
        "EVERY candidate the question's scope admits — every player who appeared, "
        "every officeholder in the span, every body in the ranking; (2) put the "
        "deciding value next to each (birth date, count, figure), cited; (3) THEN "
        "name the maximum. NEVER decide a superlative on a rounded or derived "
        "display: a coarse figure (a whole-number age, a rounded total, a bucketed "
        "rank) cannot separate two contenders that differ below its precision. "
        "Fetch the "
        "exact underlying value (full birth date, unrounded figure) for every "
        "contender, from a source that lists them ALL: a page showing only your "
        "front-runner cannot establish that nobody beats them. (3b) THEN "
        "name the maximum. Reproduce that candidate table in the proof section — "
        "a correct winner with no visible tally loses to a reference that shows "
        "its work, and 'among others' / 'and several more' is not a tally. If the "
        "pool is too large to list in full, rank it, show every contender down to a "
        "stated cutoff, and say what the cutoff was — a stated cutoff is a covered "
        "pool; an unstated one reads as an unchecked one."
    )


    def _needs_set_completeness(question: str) -> bool:
        q = " ".join((question or "").split())
        if _SET_HINT_RE.search(q):
            return True
        m = _PLURAL_HEAD_RE.search(q)
        if m and m.group(1).lower() not in _PLURAL_FALSE:
            if not _has_superlative(q) or re.search(r"\b(?:all|every|each)\b", q, re.IGNORECASE):
                return True
        return bool(re.search(r"\bwhich\b", q, re.IGNORECASE)) and bool(_SET_CONNECTIVE_RE.search(q))


    SET_RULE = (
        "SET ANSWER: this question asks for a set. Missing a qualifying member "
        "scores the same as wrong — enumerate the pool, test EVERY member against "
        "EVERY condition, and name ALL qualifiers (each with its own citations per "
        "condition). Then give EVERY excluded member its own line with the condition "
        "it fails and its own [n] — not a single clause sweeping several names "
        "together, and not just the near-misses. Never claim 'the only X' unless "
        "the whole pool was checked; if "
        "your pool may be partial, still commit to every qualifier you verified. "
        "GET THE POOL FROM A LIST, NOT MEMBER-BY-MEMBER: your FIRST retrieval for a "
        "set question should hunt the authoritative roster/list/table that "
        "enumerates the whole pool (search it AS a list — '<pool subject> list', "
        "'<pool subject> table', 'list of <pool subject>' — and read_page it). "
        "Assembling the pool from separate per-member searches is how a run ends up "
        "with 3 of 6 qualifiers: the members you never thought to search for are "
        "invisible to you. Read the roster page first, then verify each member. "
        "ONE LIST PER PERIOD, THEN JOIN: when a condition has to hold across several "
        "periods — successive years, separate editions, or two parallel events — "
        "fetch ONE roster page per period and join them on the member: one list per "
        "period, not one lookup per member. A "
        "pool of 30+ members each needing several figures is a table-join, and "
        "per-member lookups will run out of turns long before the pool is covered. "
        "UNIVERSAL conditions ('in EVERY one of them', 'for BOTH parts', 'in ALL "
        "three periods'): check each candidate against EACH "
        "instance separately, with a citation per instance — one shared instance "
        "is not enough. If NO candidate survives every instance, then 'none' IS "
        "the answer: state it as a verified fact about the world with the "
        "per-instance citations that prove it."
    )


    def _bounded_span(start, end, note_len: int) -> list[int]:
        start = max(0, min(int(start), note_len))
        end = max(start + 1, min(int(end), note_len))
        return [start, end]


    def _coalesce_spans(spans: list[list[int]]) -> list[list[int]]:
        spans.sort()
        merged: list[list[int]] = []
        for s, e in spans:
            if merged and s <= merged[-1][1]:
                merged[-1][1] = max(merged[-1][1], e)
            else:
                merged.append([s, e])
        return merged


    def _widen_citation_spans(merged: list[list[int]], note_len: int,
                              room: int) -> list[list[int]]:
        if not (merged and note_len and room):
            return merged
        extra = room // len(merged)
        for w in merged:
            pad = min(extra, max(0, CITATION_MIN_SPAN_CHARS - (w[1] - w[0])))
            if pad:
                left = min(pad // 2, w[0])
                w[0] -= left
                rest = pad - left
                right = min(rest, note_len - w[1])
                w[1] += right
                w[0] = max(0, w[0] - (rest - right))
        return _coalesce_spans(merged)


    def _citation_slices_for_row(row: dict) -> list | None:
        spans = row["spans"]
        if not spans:
            return None
        note_len = int(row["note_len"] or 0)
        shown: list[list[int]] = [
            _bounded_span(span[0], span[1], note_len) for span in spans[:4]]
        retained = [
            _bounded_span(a, b, note_len) for a, b in (row.get("retained") or [])]
        if retained:
            shown = retained
        merged = _coalesce_spans(shown)
        base = sum(e - s for s, e in merged)
        room = max(0, CITATION_MAX_REF_CHARS - base)
        merged = _widen_citation_spans(merged, note_len, room)
        slices = [CitationSlice(start=s, end=e) for s, e in merged if e > s]
        return slices or None


    class EvidenceBoard:
        def __init__(self) -> None:
            self.rows: list[dict] = []

        def add(self, receipt_id: str, result_id: str, note_len: int,
                kind: str, spans: list[tuple[int, int]] | None,
                title: str = "", url: str = "", preview: str = "",
                text: str = "") -> int:
            self.rows.append({
                "receipt_id": receipt_id,
                "result_id": result_id,
                "note_len": note_len,
                "kind": kind,
                "title": (title or "")[:160],
                "url": (url or "")[:300],
                "preview": (preview or "")[:1200],
                "spans": spans,
                "text": (text or "")[:_LEDGER_TEXT_CAP],
                "retained": [],
            })
            return len(self.rows)

        def ref_for(self, number: int) -> CitationRef | None:
            if not (1 <= number <= len(self.rows)):
                return None
            row = self.rows[number - 1]
            if row.get("kind") == "reserved":
                return None
            if not row["receipt_id"] or not row["result_id"]:
                return None
            slices = _citation_slices_for_row(row)
            if not slices:
                return None
            return CitationRef(receipt_id=row["receipt_id"],
                               result_id=row["result_id"], slices=slices)


    _WORD_RE = re.compile(r"[a-z0-9][a-z0-9'.\-]{2,}")
    _STOP = frozenset(
        "the and for with from that this have has was were are is been its their "
        "which what when where who how many much according also into over under "
        "between during against about after before while other more most than".split())


    def _key_terms(text: str) -> set[str]:
        return {w for w in _WORD_RE.findall((text or "").casefold()) if w not in _STOP}


    def _score_window_hits(note: str, terms: set[str], width: int) -> list[tuple[int, int]]:
        n = len(note)
        step = max(600, width // 3)
        low = note.lower()
        scored: list[tuple[int, int]] = []
        pos = 0
        while pos < n:
            seg = low[pos:pos + width]
            scored.append((sum(1 for t in terms if t in seg), pos))
            if pos + width >= n:
                break
            pos += step
        scored.sort(key=lambda hs: (-hs[0], hs[1]))
        return scored


    def _pick_disjoint_windows(scored: list[tuple[int, int]], n: int, width: int,
                               k: int) -> list[tuple[int, int]]:
        picked: list[tuple[int, int]] = []
        for hits, start in scored:
            if len(picked) >= max(1, k):
                break
            end = min(n, start + width)
            if any(start < pe and ps < end for ps, pe in picked):
                continue
            if picked and hits <= 0:
                continue
            picked.append((start, end))
        picked.sort()
        return picked or [(0, min(n, width))]


    def _best_windows(note: str, terms: set[str], width: int,
                      k: int = 1) -> list[tuple[int, int]]:
        n = len(note)
        if n <= width:
            return [(0, n)]
        return _pick_disjoint_windows(_score_window_hits(note, terms, width), n, width, k)


    _SLOT = "\x00{}\x00"


    class ToolOutput:

        def __init__(self, text: str, rows: list[dict] | None = None) -> None:
            self.text = text
            self.rows = rows or []


    def _commit_tool_output(out, board: EvidenceBoard) -> str:
        if isinstance(out, str):
            return out
        if not isinstance(out, ToolOutput):
            return f"# tool crashed: {out}"
        text = out.text
        for i, row in enumerate(out.rows):
            n = board.add(row["receipt_id"], row["result_id"], row["note_len"],
                           row["kind"], row["spans"], title=row.get("title", ""),
                           url=row.get("url", ""), preview=row.get("preview", ""),
                           text=row.get("text", ""))
            text = text.replace(_SLOT.format(i), str(n))
        return text

    _SITE_OP_RE = re.compile(r"\bsite:\S+\s*", re.I)


    def _degrade_query(q: str) -> str:
        out = _SITE_OP_RE.sub("", q or "").replace('"', " ")
        return " ".join(out.split())


    def _search_cite_span(n_len: int):
        if n_len >= 100:
            return [(0, min(max(SEARCH_EXCERPT_CHARS, 100), n_len))]
        if n_len:
            return [(0, n_len)]
        return None


    def _search_row_from_item(receipt: str, item) -> dict | None:
        rid = getattr(item, "result_id", None)
        if not isinstance(rid, str) or not rid:
            return None
        note = (getattr(item, "note", None) or "")
        if not note.strip():
            return None
        n_len = len(note)
        title = (getattr(item, "title", None) or "").strip()
        url = (getattr(item, "url", None) or "").strip()
        return {"receipt_id": receipt, "result_id": rid, "note_len": n_len,
                "kind": "search", "spans": _search_cite_span(n_len), "title": title,
                "url": url, "preview": note[:SEARCH_EXCERPT_CHARS], "text": note}


    async def _do_search(query_text: str, board: EvidenceBoard):
        if not query_text.strip():
            return "# web_search: empty query"
        payload = None
        fired: set[str] = set()
        for attempt, allow_repeat in ((query_text, False), (query_text, True),
                                      (_degrade_query(query_text), False)):
            if not attempt.strip() or (attempt in fired and not allow_repeat):
                continue
            fired.add(attempt)
            try:
                payload = await search_web(attempt, provider=SEARCH_PROVIDER, num=8,
                                           timeout=SEARCH_TIMEOUT_S)
                if getattr(payload, "results", None):
                    break
            except Exception:
                payload = None
        if payload is None:
            return f"# web_search({query_text!r}) failed"
        _spend_note(payload)
        receipt = str(getattr(payload, "receipt_id", "") or "")
        results = list(getattr(payload, "results", None) or [])
        if not receipt:
            return f"# web_search({query_text!r}): no citable results"
        rows: list[dict] = []
        lines = [f"# web_search({query_text!r}): {len(results)} results"]
        for item in results:
            row = _search_row_from_item(receipt, item)
            if row is None:
                continue
            rows.append(row)
            lines.append(f"[{_SLOT.format(len(rows) - 1)}] {row['title']} — {row['url']}"
                         f"\n    {row['preview']}")
        return ToolOutput("\n".join(lines), rows)


    def _render_fetched_note(url: str, receipt: str, rid: str, note: str,
                             question: str, focus: str):
        if len(note) <= FETCH_PLAIN_CHARS:
            row = {"receipt_id": receipt, "result_id": rid, "note_len": len(note),
                   "kind": "fetch", "spans": [(0, len(note))], "title": url,
                   "url": url, "preview": note[:1200], "text": note}
            return ToolOutput(f"# read_page({url!r}) -> [{_SLOT.format(0)}] full page, "
                              f"{len(note)} chars\n{note}", [row])
        terms = _key_terms(question) | _key_terms(focus)
        windows = _best_windows(note, terms, FETCH_WINDOW_CHARS, k=FETCH_WINDOWS_PER_PAGE)
        row = {"receipt_id": receipt, "result_id": rid, "note_len": len(note),
               "kind": "fetch", "spans": [(0, FETCH_HEAD_CHARS)] + list(windows),
               "title": url, "url": url,
               "preview": note[windows[0][0]:windows[0][0] + 1200], "text": note}
        head = note[:FETCH_HEAD_CHARS]
        sections = "".join(
            f"\n--- section @{s} ---\n{note[s:e]}" for s, e in windows)
        return ToolOutput(f"# read_page({url!r}) -> [{_SLOT.format(0)}] {len(note)} chars total; head + "
                f"the {len(windows)} most relevant section(s) shown "
                f"({', '.join(f'{s}-{e}' for s, e in windows)}). If the answer set may "
                f"continue elsewhere in this page, call read_page again with a "
                f"different focus.\n--- head ---\n{head}{sections}", [row])


    async def _do_fetch(url: str, focus: str, question: str, board: EvidenceBoard) -> str:
        if not url.strip():
            return "# read_page: empty url"
        payload = None
        for _attempt in (0, 1):
            try:
                payload = await fetch_page(url, provider=SEARCH_PROVIDER, timeout=FETCH_TIMEOUT_S)
                if getattr(payload, "results", None):
                    break
            except Exception:
                payload = None
        if payload is None:
            return f"# read_page({url!r}) failed"
        _spend_note(payload)
        receipt = str(getattr(payload, "receipt_id", "") or "")
        results = list(getattr(payload, "results", None) or [])
        if not results or not receipt:
            return f"# read_page({url!r}): no content"
        item = results[0]
        rid = getattr(item, "result_id", None)
        note = getattr(item, "note", None) or ""
        if not isinstance(rid, str) or not rid or not note.strip():
            return f"# read_page({url!r}): no usable content"
        return _render_fetched_note(url, receipt, rid, note, question, focus)


    _SEC_TICKERS_URL = "https://www.sec.gov/files/company_tickers.json"
    _SEC_SUBMISSIONS_URL = "https://data.sec.gov/submissions/CIK{cik10}.json"
    _SEC_DOC_URL = "https://www.sec.gov/Archives/edgar/data/{cik}/{accession}/{doc}"
    _SEC_FETCH_TIMEOUT_S = 26.0
    _SEC_MIN_HEADROOM_S = 40.0
    _SEC_CACHE: dict = {}
    _SEC_STOPWORDS = frozenset(
        "inc incorporated corp corporation company companies co ltd limited llc plc "
        "lp llp group holdings the".split())
    _SEC_ALNUM_RE = re.compile(r"[a-z0-9]+")


    def _sec_tokens(text: str) -> list[str]:
        return [w for w in _SEC_ALNUM_RE.findall((text or "").lower())
                if w not in _SEC_STOPWORDS]


    def _sec_norm_form(form: str) -> str:
        f = " ".join((form or "").upper().replace("FORM", " ").split())
        m = re.fullmatch(r"(\d{1,2})\s*-?\s*([A-Z])", f)
        if m:
            return f"{m.group(1)}-{m.group(2)}"
        m = re.fullmatch(r"(DEF)\s*-?\s*(14A)", f)
        if m:
            return "DEF 14A"
        return f


    async def _fetch_json(url: str, deadline: float):
        cached = _SEC_CACHE.get(url)
        if cached is not None:
            return cached
        for _attempt in (0, 1):
            left = deadline - monotonic()
            if left < 12.0:
                return None
            try:
                payload = await asyncio.wait_for(
                    fetch_page(url, provider=SEARCH_PROVIDER,
                               timeout=min(_SEC_FETCH_TIMEOUT_S, left - 6.0)),
                    timeout=min(_SEC_FETCH_TIMEOUT_S, left - 6.0) + 4.0)
            except Exception:
                continue
            _spend_note(payload)
            results = list(getattr(payload, "results", None) or [])
            note = (getattr(results[0], "note", None) or "") if results else ""
            start = note.find("{")
            end = note.rfind("}")
            if start == -1 or end <= start:
                continue
            try:
                obj = json.loads(note[start:end + 1])
            except Exception:
                continue
            if isinstance(obj, dict):
                _SEC_CACHE[url] = obj
                return obj
        return None


    def _sec_pick_filing(recent: dict, form: str, year: str):
        forms = recent.get("form"); accs = recent.get("accessionNumber")
        docs = recent.get("primaryDocument"); rdates = recent.get("reportDate")
        fdates = recent.get("filingDate")
        if not (isinstance(forms, list) and isinstance(accs, list) and isinstance(docs, list)):
            return None
        n = min(len(forms), len(accs), len(docs))
        form_norm = _sec_norm_form(form)
        best_year = None
        best_any = None
        for i in range(n):
            if _sec_norm_form(str(forms[i])) != form_norm:
                continue
            if accs[i] is None or docs[i] is None:
                continue
            acc = str(accs[i]); doc = str(docs[i])
            if not acc or not (doc.endswith(".htm") or doc.endswith(".html")):
                continue
            rd = str(rdates[i]) if (isinstance(rdates, list) and i < len(rdates)
                                    and rdates[i] is not None) else ""
            fd = str(fdates[i]) if (isinstance(fdates, list) and i < len(fdates)
                                    and fdates[i] is not None) else ""
            key = rd or fd
            if best_any is None or key > best_any[0]:
                best_any = (key, acc, doc)
            if year and rd[:4] == year:
                if best_year is None or key > best_year[0]:
                    best_year = (key, acc, doc)
        pick = best_year if year else best_any
        if pick is None:
            return None
        return pick[1], pick[2]


    _SEC_SEARCH_HINT = "search \"site:sec.gov {company} {year} {form}\" and read_page the Archives result"


    async def _do_sec_filing(company: str, form: str, year: str, deadline: float) -> str:
        company = (company or "").strip()
        form = (form or "").strip() or "10-K"
        year = (year or "").strip()[:4]
        hint = _SEC_SEARCH_HINT.format(company=company, year=year, form=form)
        if not company:
            return "# sec_filing: company required"
        if (deadline - monotonic()) < _SEC_MIN_HEADROOM_S:
            return f"# sec_filing: skipped (low time) — {hint}"
        tickers = await _fetch_json(_SEC_TICKERS_URL, deadline)
        if not isinstance(tickers, dict):
            return f"# sec_filing: EDGAR ticker index unavailable — {hint}"
        want = _sec_tokens(company)
        best = None
        for row in tickers.values():
            if not isinstance(row, dict):
                continue
            title = str(row.get("title", ""))
            ticker = str(row.get("ticker", "")).lower()
            words = set(_sec_tokens(title))
            n_hit = sum(1 for w in want if w in words)
            if len(want) == 1 and ticker == want[0]:
                score = 100
            elif want and n_hit == len(want):
                score = 50 + n_hit
            else:
                continue
            cand = (score, -len(title), str(row.get("cik_str", "")).zfill(10), title)
            if best is None or cand > best:
                best = cand
        if best is None:
            return f"# sec_filing({company!r}): no confident EDGAR match — {hint}"
        cik10, title = best[2], best[3]
        subs = await _fetch_json(_SEC_SUBMISSIONS_URL.format(cik10=cik10), deadline)
        filings = subs.get("filings") if isinstance(subs, dict) else None
        recent = filings.get("recent") if isinstance(filings, dict) else None
        if not isinstance(recent, dict):
            return f"# sec_filing({company!r}): EDGAR submissions unavailable for {title} — {hint}"
        pick = _sec_pick_filing(recent, form, year)
        if pick is None:
            return (f"# sec_filing({company!r}, {form!r}, year={year or 'latest'}): no matching "
                    f"filing in EDGAR's recent index for {title} — check the form/year, or {hint}")
        accession, doc = pick
        url = _SEC_DOC_URL.format(cik=cik10.lstrip("0") or cik10,
                                  accession=accession.replace("-", ""), doc=doc)
        return (f"# sec_filing -> {title} {form} {year or '(latest)'} primary document:\n"
                f"{url}\nNow call read_page on this URL with a focus hint for the "
                f"section you need, and cite figures from that read_page result.")


    def _ledger_page(url: str, board: EvidenceBoard) -> tuple[int, dict] | None:
        u = (url or "").strip().rstrip("/")
        if not u:
            return None
        for i in range(len(board.rows) - 1, -1, -1):
            row = board.rows[i]
            if not row.get("text"):
                continue
            r = str(row.get("url") or "").rstrip("/")
            if r == u or r.endswith(u) or u.endswith(r):
                return i + 1, row
        return None


    def _do_page_grep(url: str, pattern: str, board: EvidenceBoard) -> str:
        hit = _ledger_page(url, board)
        if hit is None:
            return f"# page_grep: {url!r} has not been fetched this run; call read_page first"
        n, row = hit
        text = row.get("text") or ""
        pat = (pattern or "").strip()
        if not pat:
            return "# page_grep: empty pattern"
        try:
            rx = re.compile(pat, re.I)
        except re.error:
            rx = re.compile(re.escape(pat), re.I)
        out, seen_at = [], []
        for m in rx.finditer(text):
            c = (m.start() + m.end()) // 2
            if any(abs(c - prev) < PAGE_GREP_WINDOW // 2 for prev in seen_at):
                continue
            seen_at.append(c)
            a = max(0, c - PAGE_GREP_WINDOW // 2)
            b = min(len(text), a + PAGE_GREP_WINDOW)
            out.append(f"\n--- match @{a} ---\n{text[a:b]}")
            if len(out) >= PAGE_GREP_MAX_HITS:
                break
        if not out:
            return (f"# page_grep({pat!r}) on [{n}]: no match in {len(text)} chars. "
                    f"Try a shorter or looser pattern.")
        return (f"# page_grep({pat!r}) on [{n}] -> {len(out)} match(es) of {len(text)} chars"
                + "".join(out))


    def _do_page_read(url: str, offset: int, length: int, board: EvidenceBoard) -> str:
        hit = _ledger_page(url, board)
        if hit is None:
            return f"# page_read: {url!r} has not been fetched this run; call read_page first"
        n, row = hit
        text = row.get("text") or ""
        a = max(0, min(int(offset or 0), max(0, len(text) - 1)))
        ln = int(length or PAGE_READ_MAX_CHARS)
        b = min(len(text), a + max(1, min(ln, PAGE_READ_MAX_CHARS)))
        return f"# page_read([{n}] @{a}:{b} of {len(text)})\n{text[a:b]}"


    def _do_retain_evidence(source: str, quote: str, board: EvidenceBoard) -> str:
        raw = (source or "").strip().strip("[]")
        try:
            n = int(raw)
        except ValueError:
            return f"# retain_evidence: source must be a result number like [3], got {source!r}"
        if not (1 <= n <= len(board.rows)):
            return f"# retain_evidence: no result [{n}] exists yet"
        row = board.rows[n - 1]
        text = row.get("text") or ""
        q = (quote or "").strip()
        if len(q) < RETAIN_MIN_QUOTE:
            return (f"# retain_evidence: quote too short ({len(q)} chars); quote at least "
                    f"{RETAIN_MIN_QUOTE} characters of the source text")
        if not text:
            return f"# retain_evidence: result [{n}] has no stored text to quote from"
        i = text.find(q)
        if i < 0:
            i = text.lower().find(q.lower())
        if i < 0:
            squashed = " ".join(q.split())
            i = " ".join(text.split()).lower().find(squashed.lower())
            if i >= 0:
                i = -1
        if i < 0:
            return (f"# retain_evidence: that text does not appear in [{n}]. Quote it "
                    f"EXACTLY as the source prints it, or read more of the page first.")
        kept = row.setdefault("retained", [])
        if len(kept) >= RETAIN_MAX_PER_ROW:
            return f"# retain_evidence: [{n}] already has {len(kept)} retained excerpts"
        a = max(0, i - RETAIN_MARGIN_CHARS)
        b = min(int(row.get("note_len") or len(text)), i + len(q) + RETAIN_MARGIN_CHARS)
        if b <= a:
            return f"# retain_evidence: could not bound the excerpt in [{n}]"
        kept.append((a, b))
        return (f"# retain_evidence: kept {b - a} chars of [{n}] around your quote. "
                f"Cite [{n}] for that claim.")


    def _parse_tool_call(call) -> tuple[str, dict]:
        try:
            args = json.loads(getattr(call, "arguments", None) or "{}")
        except Exception:
            args = {}
        if not isinstance(args, dict):
            args = {}
        name = getattr(call, "name", "") or ""
        return name, args


    async def _run_tool(call, question: str, board: EvidenceBoard, deadline: float) -> str:
        name, args = _parse_tool_call(call)
        if name == "web_search":
            return await _do_search(str(args.get("query") or ""), board)
        if name == "read_page":
            return await _do_fetch(str(args.get("url") or ""), str(args.get("focus") or ""),
                                   question, board)
        if name == "retain_evidence":
            return _do_retain_evidence(str(args.get("source") or ""),
                                       str(args.get("quote") or ""), board)
        if name == "page_grep":
            return _do_page_grep(str(args.get("url") or ""),
                                 str(args.get("pattern") or ""), board)
        if name == "page_read":
            return _do_page_read(str(args.get("url") or ""),
                                 args.get("offset") or 0,
                                 args.get("length") or PAGE_READ_MAX_CHARS, board)
        if name == "sec_filing":
            return await _do_sec_filing(str(args.get("company") or ""),
                                        str(args.get("form") or ""),
                                        str(args.get("year") or ""), deadline)
        return f"# unknown tool {name!r}"


    _REASONING_MANDATORY = ("openai/gpt-oss",)


    def _least_think(lane: str, model: str = "") -> dict:
        for prefix in _REASONING_MANDATORY:
            if model.startswith(prefix):
                return {"enabled": True, "effort": "low"}
        return {"enabled": False}


    _FAST_UPSTREAMS = ("Decart", "CoreWeave", "Alibaba")
    _FAST_UPSTREAMS_OSS = ("Cerebras", "Groq", "BaseTen")


    def _upstream(lane: str, model: str) -> dict | None:
        if lane != LLM_LANE_A:
            return None
        if model.startswith("z-ai/glm-5.2"):
            only = _FAST_UPSTREAMS
        elif model.startswith("openai/gpt-oss"):
            only = _FAST_UPSTREAMS_OSS
        else:
            return None
        return {"provider": {"only": list(only), "allow_fallbacks": True}}


    async def _chat_simple(lane: str, model: str, system: str, user: str, *,
                           max_tokens: int, timeout: float,
                           think: dict | None = None) -> str:
        if think is None:
            think = _least_think(lane, model)
        _pin0 = _upstream(lane, model)
        payload = None
        for _pin in ((_pin0, None) if _pin0 is not None else (None,)):
            try:
                payload = await llm_chat(
                    provider=lane,
                    model=model,
                    messages=[{"role": "system", "content": system},
                              {"role": "user", "content": user}],
                    temperature=0.15,
                    max_output_tokens=max_tokens,
                    timeout=timeout,
                    thinking=think,
                    provider_extra=_pin,
                )
                break
            except Exception:
                if _pin is None:
                    raise
                continue
        _spend_note(payload)
        return _plain_text_from_chat(payload)


    class _EmptyChoiceMessage:
        content = ""
        tool_calls = ()


    class _EmptyChoice:
        message = _EmptyChoiceMessage()


    class _EmptyLlm:
        raw_text = ""
        choices = (_EmptyChoice(),)


    class _EmptyTurn:
        llm = _EmptyLlm()
        budget = None


    _EMPTY_TURN = _EmptyTurn()


    def _loop_lane_rungs():
        return ((LLM_LANE_A, LOOP_MODEL_A, True),
                (LLM_LANE_A, LOOP_MODEL_A, False),
                (LLM_LANE_B, LOOP_MODEL_B, False))


    def _message_payload_chars(messages: list[dict]) -> int:
        return sum(len(str(msg.get("content") or "")) for msg in messages
                   if isinstance(msg, dict))


    def _plain_text_from_chat(payload) -> str:
        llm = getattr(payload, "llm", None)
        text = (getattr(llm, "raw_text", None) or "").strip()
        if text:
            return text
        choices = getattr(llm, "choices", None) or []
        if choices:
            content = getattr(choices[0].message, "content", None)
            if isinstance(content, str):
                return content.strip()
        return ""


    async def _chat_turn(messages: list[dict], deadline: float, *, finish_only: bool,
                         force_tools: bool = False):
        turn_wall = monotonic() + TURN_TIMEOUT_S + 35.0
        payload_chars = _message_payload_chars(messages)
        for lane_model in _loop_lane_rungs():
            lane = lane_model[0]
            model = lane_model[1]
            pinned = lane_model[2]
            if model == LOOP_MODEL_B and payload_chars > LANE_B_MAX_PAYLOAD_CHARS:
                return _EMPTY_TURN
            timeout = min(TURN_TIMEOUT_S, deadline - monotonic() - 5.0,
                          turn_wall - monotonic())
            if timeout <= 5.0:
                return None
            try:
                payload = await asyncio.wait_for(llm_chat(
                    provider=lane,
                    model=model,
                    messages=messages,
                    tools=LOOP_TOOLS if (force_tools or not finish_only) else None,
                    tool_choice="auto" if (force_tools or not finish_only) else None,
                    temperature=0.2,
                    thinking=({"enabled": False} if (finish_only and model == LOOP_MODEL_B)
                              else {"enabled": True, "effort": "low"}),
                    max_output_tokens=6000 if (finish_only and model == LOOP_MODEL_B) else None,
                    provider_extra=_upstream(lane, model) if pinned else None,
                    timeout=timeout,
                ), timeout=min(timeout + 6.0,
                               max(1.0, deadline - monotonic() - 1.0)))
                _spend_note(payload)
                return payload
            except Exception:
                continue
        return None


    async def _knowledge_brief(question: str) -> tuple[str, str]:
        system = ("Senior research analyst. Commit to concrete best answers from "
                  "knowledge; mark uncertain values (verify). Never refuse.")
        user = (
            f"Question:\n{question}\n\n"
            "Fill in this internal worksheet. It is planning scratch for your own use, "
            "never an answer, so keep the tags lowercase and never reuse them as "
            "section headings later.\n"
            "draft: your full best answer now — candidate pool, every stated "
            "condition applied, qualifying entities with figures/dates, near-miss "
            "exclusions. Flag shaky facts with (verify).\n"
            "conditions: each atomic condition in the question, numbered, including "
            "any output-format demand.\n"
            "searches: 3-6 precise web searches for the facts that decide the answer "
            "(entity + metric + year; include a named source's site: filter).\n"
            "urls: up to 5 exact URLs worth reading directly (official stats pages, "
            "sec.gov Archives filings, boxofficemojo year pages); 'none' if unsure."
        )
        raw = ""
        try:
            raw = await _chat_simple(LLM_LANE_A, LOOP_MODEL_A, system, user,
                                     max_tokens=2400, timeout=BRIEF_TIMEOUT_S,
                                     think=_least_think(LLM_LANE_A, LOOP_MODEL_A))
        except Exception:
            try:
                raw = await _chat_simple(LLM_LANE_B, LOOP_MODEL_B, system, user,
                                         max_tokens=2400, timeout=BRIEF_TIMEOUT_S,
                                         think=_least_think(LLM_LANE_B, LOOP_MODEL_B))
            except Exception:
                raw = ""
        if not raw:
            return "", ""
        draft = raw
        cut = min((mm.start() for mm in (
            re.search(r"[#*_\s]*(?:conditions|CHECKLIST)[#*_\s]*:", raw, re.IGNORECASE),
            re.search(r"^[ \t]*[#*_>]{0,4}[ \t]*(?:conditions|CHECKLIST)[ \t]*[#*_]{0,3}[ \t]*$",
                      raw, re.IGNORECASE | re.MULTILINE),
        ) if mm is not None), default=None)
        if cut is not None:
            draft = raw[:cut]
        draft = re.sub(r"^[#*_\s]*(?:draft|BEST ANSWER)[#*_\s]*:[#*_\s]*", "", draft,
                       flags=re.IGNORECASE)
        draft = re.sub(r"^[ \t]*[#*_>]{0,4}[ \t]*(?:draft|BEST ANSWER)[ \t]*[#*_]{0,3}[ \t]*\n+",
                       "", draft, flags=re.IGNORECASE)
        draft = draft.strip()
        brief = ("PRIOR ANALYSIS — your own planning worksheet (verify anything marked "
                 "(verify), and correct it wherever tool results disagree). Its tags are "
                 "internal: never reproduce them, or any section named after them, in the "
                 "answer.\n" + raw.strip())
        return draft, brief


    _SEED_TOKEN_RE = re.compile(r"[A-Za-z0-9][A-Za-z0-9.\-']+")
    _SEED_STOP = frozenset("name list give tell show find identify please could would "
                           "you your can may might should must let make sure both also".split())
    MAX_SEED_QUERIES = 3


    def _seed_queries(question: str, set_question: bool) -> list[str]:
        q = " ".join((question or "").split())
        if not q:
            return []
        seeds = [q[:300]]
        salient = [t for t in _SEED_TOKEN_RE.findall(q)
                   if len(t) >= 3 and t.lower() not in _STOP and t.lower() not in _SEED_STOP]
        if len(salient) >= 2:
            seeds.append(" ".join(salient[:8]))
        if set_question and salient:
            seeds.append("list of " + " ".join(salient[:6]))
        out: list[str] = []
        for s in seeds:
            s = s.strip()
            if s and s not in out:
                out.append(s)
        return out[:MAX_SEED_QUERIES]


    async def _preseed(question: str, set_question: bool, board: EvidenceBoard,
                       deadline: float) -> str:
        seeds = _seed_queries(question, set_question)
        if not seeds or (deadline - monotonic()) < 40.0:
            return ""
        blocks: list = []
        for seed in seeds:
            if (deadline - monotonic()) < 30.0:
                break
            try:
                out = await asyncio.wait_for(_do_search(seed, board),
                                              timeout=SEARCH_TIMEOUT_S * 2 + 6.0)
                blocks.append(_commit_tool_output(out, board))
            except Exception:
                continue
        good = [b for b in blocks if isinstance(b, str) and _CITE_MARK_RE.search(b)]
        if not good:
            return ""
        return ("Automatic first-pass searches (already numbered — cite these [n] "
                "directly, and search further as needed):\n\n" + "\n".join(good))


    async def _prime_research_messages(question: str, brief: str, board: EvidenceBoard,
                                       deadline: float) -> list[dict]:
        set_q = _needs_set_completeness(question)
        messages = [{"role": "system", "content": LOOP_RULES}]
        if set_q:
            messages.append({"role": "system", "content": SET_RULE})
        if _needs_superlative_proof(question):
            messages.append({"role": "system", "content": SUPERLATIVE_RULE})
        if brief:
            messages.append({"role": "system", "content": brief})
        seeded = await _preseed(question, set_q, board, deadline)
        if seeded:
            messages.append({"role": "system", "content": seeded})
        messages.append({"role": "user", "content": question})
        return messages


    def _finish_candidate_text(llm, msg) -> str:
        candidate = (getattr(llm, "raw_text", None) or "").strip()
        if not candidate:
            content = getattr(msg, "content", None)
            if isinstance(content, str):
                candidate = content.strip()
        return candidate


    async def _fanout_tool_calls(run_calls, question: str, board: EvidenceBoard,
                                 deadline: float) -> list:
        tool_budget = max(_TOOL_PHASE_MIN_S, min(FETCH_TIMEOUT_S * 2 + _TOOL_PHASE_PAD_S,
                                                 deadline - monotonic() - MIN_TAIL_S))
        tool_tasks = [asyncio.ensure_future(_run_tool(c, question, board, deadline))
                      for c in run_calls]
        try:
            await asyncio.wait(tool_tasks, timeout=tool_budget)
        except Exception:
            pass
        results = []
        for t in tool_tasks:
            if t.done():
                try:
                    results.append(t.result())
                except Exception as exc:
                    results.append(f"{_TOOL_CRASH_PREFIX}{exc}")
            else:
                t.cancel()
                results.append(_TOOL_TIMEOUT_REPLY)
        return results


    def _record_tool_replies(messages: list[dict], run_calls, results, calls,
                             board: EvidenceBoard) -> None:
        for call_result in zip(run_calls, results):
            call = call_result[0]
            body = _commit_tool_output(call_result[1], board)
            messages.append({"role": "tool", "tool_call_id": call.id, "content": body})
        for call in calls[_TURN_TOOL_FANOUT:]:
            messages.append({"role": "tool", "tool_call_id": call.id,
                             "content": _TOOL_SKIP_REPLY})


    async def _execute_research_loop(question: str, brief: str, board: EvidenceBoard,
                    deadline: float, turn_cap: int,
                    carry: list[dict] | None = None,
                    allow_tools_in_wrapup: bool = False) -> tuple[str, list[dict]]:
        if carry is not None:
            messages = carry
        else:
            messages = await _prime_research_messages(question, brief, board, deadline)

        answer = ""
        ordered_wrapup = False
        repairs_left = ANSWER_REPAIR_TURNS
        for turn in range(1, turn_cap + 1):
            left = _wall_remaining(deadline)
            if left <= MIN_TAIL_S:
                break
            out_of_time = left <= WRAPUP_AT_S
            out_of_spend = _spend_left() <= WRAPUP_MIN_USD
            finish_only = out_of_time or out_of_spend or turn >= turn_cap
            if (finish_only or turn >= turn_cap - 1) and not ordered_wrapup:
                messages.append({"role": "system", "content": _wrapup_order(left)})
                ordered_wrapup = True

            payload = await _chat_turn(messages, deadline, finish_only=finish_only,
                                       force_tools=allow_tools_in_wrapup and turn == 1)
            if payload is None:
                break
            llm = getattr(payload, "llm", None)
            choices = getattr(llm, "choices", None) or []
            if not choices:
                break
            msg = choices[0].message
            calls = getattr(msg, "tool_calls", None) or ()
            if not calls:
                candidate = _finish_candidate_text(llm, msg)
                if not _is_usable_answer(candidate):
                    if repairs_left > 0 and _wall_remaining(deadline) > MIN_TAIL_S + _REPAIR_EXTRA_HEADROOM_S:
                        repairs_left -= 1
                        messages.append({"role": "system", "content": _REPAIR_ORDER})
                        answer = ""
                        continue
                    answer = ""
                    break
                answer = candidate
                messages.append({"role": "assistant", "content": answer})
                break
            messages.append(msg.to_input_message())
            run_calls = calls[:_TURN_TOOL_FANOUT]
            results = await _fanout_tool_calls(run_calls, question, board, deadline)
            _record_tool_replies(messages, run_calls, results, calls, board)
        return answer, messages


    async def _verify_and_refine(question: str, answer: str, messages: list[dict],
                           board: EvidenceBoard, deadline: float) -> str:
        probe = (
            "Audit the answer against the question. JSON only, keys: "
            '"unanswered_parts" (list; question elements not addressed), '
            '"uncited_facts" (list; load-bearing claims without [n]), '
            '"wrong_kind" (list; places where the named entity is a different KIND '
            "than the question asks — a person instead of a series, a duo instead "
            "of a show), "
            '"incomplete_roster" (list; THE MOST COMMON LOSS. If the question ranges '
            "over a candidate pool — a closed set that can be enumerated, or several "
            "conditions applied to a class — then: is the pool itself stated and "
            "plausibly COMPLETE, and does the answer give a verdict for EVERY member "
            "(qualifies / excluded because X, each cited)? Name any pool member the "
            "answer never mentions, and say so if the pool looks truncated — an "
            "answer naming 3 qualifiers when the pool holds 6 scores as WRONG, not "
            "partial), "
            '"thin_proof" (list; a qualifier lacking a per-condition citation, or a '
            "plausible near-miss candidate never addressed), "
            '"hand_waved_tally" (list; for a superlative/count/most-common question: '
            "the answer asserts a winner or a count WITHOUT showing the candidate "
            "table it was derived from. Phrases like 'among others', 'and several "
            "more', 'multiple X', or naming 2 examples to justify a count are all "
            "hand-waving — say so and name what the tally must list). "
            "Empty lists when clean.\n\n"
            f"Question:\n{question}\n\nAnswer:\n{answer[:11000]}"
        )
        try:
            raw = await _chat_simple(LLM_LANE_A, AUDIT_MODEL,
                                     "Strict completeness auditor. JSON only.",
                                     probe, max_tokens=2200,
                                     timeout=max(8.0, min(AUDIT_TIMEOUT_S,
                                                          (deadline - monotonic()) - 72.0)))
            raw = re.sub(r"^```(?:json)?\s*|\s*```$", "", raw.strip(), flags=re.I | re.M)
            report = json.loads(raw)
        except Exception:
            return answer
        gaps: list[str] = []
        roster_gaps: list[str] = []
        if isinstance(report, dict):
            for key in ("incomplete_roster", "hand_waved_tally", "unanswered_parts",
                        "uncited_facts", "wrong_kind", "thin_proof"):
                vals = report.get(key)
                if isinstance(vals, list):
                    found = [str(v) for v in vals if str(v).strip()]
                    if key in ("incomplete_roster", "hand_waved_tally"):
                        roster_gaps.extend(found)
                    gaps.extend(found)
        if not gaps or (deadline - monotonic()) < 70.0:
            return answer
        order = ("AUDIT: the answer has gaps:\n- " + "\n- ".join(gaps[:6]))
        if roster_gaps:
            order += ("\nThe candidate pool is incomplete — this loses outright. FIRST "
                      "search for the authoritative LIST/roster/table that enumerates "
                      "the whole pool (query it as a list, e.g. '<pool subject> full "
                      "list', not one member at a time), verify EVERY member against "
                      "every condition, then rewrite.")
        order += ("\nUse at most 3 tool calls to close the most important gaps, then "
                  "rewrite the COMPLETE final answer with [n] citations in the "
                  "required shape.")
        messages.append({"role": "system", "content": order})
        patched, _ = await _execute_research_loop(question, "", board, deadline,
                                 AUDIT_EXTRA_TURNS + 1, carry=messages,
                                 allow_tools_in_wrapup=True)
        patched = patched.strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.6):
            return answer
        return patched


    _UN_Q_RE = re.compile(
        r"\bin (millions?|billions?|thousands?)(?: of)? (USD|EUR|GBP|dollars|euros|"
        r"pounds)\b|\bin (USD|EUR|GBP|km|kilometers|miles|meters|feet|hectares|"
        r"acres|tonnes|tons|kg|kilograms|pounds|percent|%)\b", re.IGNORECASE)
    _UN_SYM = {"usd": "$", "dollars": "$", "eur": "€", "euros": "€",
               "gbp": "£", "pounds": "£"}


    def _unit_demand(question: str) -> str:
        m = _UN_Q_RE.search(question or "")
        if not m:
            return ""
        return " ".join(g.lower() for g in m.groups() if g)


    def _unit_satisfied(answer: str, demand: str) -> bool:
        if not demand:
            return True
        a = (answer or "").lower()
        toks = demand.split()
        hits = 0
        for t in toks:
            sym = _UN_SYM.get(t)
            if t.rstrip("s") in a or (sym and sym in (answer or "")):
                hits += 1
        return hits >= len(toks)


    async def _unit_repair(question: str, answer: str, messages: list[dict],
                           board: EvidenceBoard, deadline: float) -> str:
        if (deadline - monotonic()) < 70.0 or _spend_left() <= AUDIT_MIN_USD:
            return answer
        demand = _unit_demand(question)
        if not demand or _unit_satisfied(answer, demand):
            return answer
        if not re.search(r"\d", answer or ""):
            return answer
        order = (f"UNIT CHECK: the question demands figures in '{demand}' but the "
                 "answer's numbers do not carry that unit/currency/scale. Convert "
                 "or annotate EVERY load-bearing figure to the demanded unit "
                 "(keep the source's verbatim value alongside if it differs), do "
                 "not change any underlying value, then rewrite the COMPLETE final "
                 "answer with [n] citations.")
        messages.append({"role": "system", "content": order})
        patched, _ = await _execute_research_loop(question, "", board, deadline, 2,
                                 carry=messages, allow_tools_in_wrapup=False)
        patched = (patched or "").strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.6):
            return answer
        return patched


    _FM_TABLE_RE = re.compile(r"\b(?:as|in) a table\b|\btable format\b", re.IGNORECASE)
    _FM_PERLINE_RE = re.compile(r"\bone per line\b|\beach on (?:a|its own) (?:new )?line\b",
                                re.IGNORECASE)
    _FM_COMMA_RE = re.compile(r"\bcomma[- ]separated\b", re.IGNORECASE)
    _FM_ALPHA_RE = re.compile(r"\b(?:sorted?|order(?:ed)?) alphabetical(?:ly)?\b"
                              r"|\balphabetical order\b", re.IGNORECASE)
    _FM_LIST_LINE_RE = re.compile(r"^\s*(?:[-*\u2022]|\d+[.)])\s+(\S.*)$", re.MULTILINE)


    def _format_gaps(question: str, answer: str) -> list[str]:
        q = question or ""
        a = answer or ""
        gaps = []
        if _FM_TABLE_RE.search(q) and a.count("|") < 4:
            gaps.append("a markdown TABLE")
        if _FM_PERLINE_RE.search(q) and len(_FM_LIST_LINE_RE.findall(a)) < 2 \
                and a.count("\n") < 2:
            gaps.append("one item PER LINE")
        if _FM_COMMA_RE.search(q):
            lead = a.split("\n", 1)[0]
            if "," not in lead:
                gaps.append("a COMMA-SEPARATED list in the first line")
        if _FM_ALPHA_RE.search(q):
            items = [m.strip().lower() for m in _FM_LIST_LINE_RE.findall(a)]
            if len(items) >= 3 and items != sorted(items):
                gaps.append("ALPHABETICAL order")
        return gaps


    async def _format_repair(question: str, answer: str, messages: list[dict],
                             board: EvidenceBoard, deadline: float) -> str:
        if (deadline - monotonic()) < 65.0 or _spend_left() <= WRAPUP_MIN_USD:
            return answer
        gaps = _format_gaps(question, answer)
        if not gaps:
            return answer
        order = ("FORMAT CHECK: the question explicitly demands " + "; ".join(gaps) +
                 " and the answer does not comply. Reshape the SAME content into the "
                 "demanded format — change no values, drop no members, keep every "
                 "[n] citation attached to its claim — then output the COMPLETE "
                 "final answer.")
        messages.append({"role": "system", "content": order})
        patched, _ = await _execute_research_loop(question, "", board, deadline, 2,
                                 carry=messages, allow_tools_in_wrapup=False)
        patched = (patched or "").strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.5):
            return answer
        return patched


    _BRACKET_FIX = {0x3010: "[", 0x3011: "]", 0xFF3B: "[", 0xFF3D: "]",
                    0xFF08: "(", 0xFF09: ")", 0x2011: "-", 0x2212: "-"}
    for _d in range(10):
        _BRACKET_FIX[0xFF10 + _d] = chr(48 + _d)


    def _normalize_brackets(text: str) -> str:
        return (text or "").translate(_BRACKET_FIX)


    _CITE_NUM_RE = re.compile(r"\[([0-9][0-9,\s\-]*)\]")


    def _remember_cite(n: int, top: int, seen: set[int], out: list[int]) -> None:
        if 1 <= n <= top and n not in seen:
            seen.add(n)
            out.append(n)


    def _cited_numbers(answer: str, top: int) -> list[int]:
        answer = _normalize_brackets(answer)
        seen: set[int] = set()
        out: list[int] = []
        for m in _CITE_NUM_RE.finditer(answer):
            for chunk in m.group(1).split(","):
                piece = chunk.strip()
                span = re.fullmatch(r"(\d{1,4})\s*-\s*(\d{1,4})", piece)
                if span:
                    lo = int(span.group(1))
                    hi = int(span.group(2))
                    for n in range(lo, min(hi, lo + 16) + 1):
                        _remember_cite(n, top, seen, out)
                elif piece.isdigit():
                    _remember_cite(int(piece), top, seen, out)
        return out


    _OUTPUT_ONLY_RE = re.compile(
        r"\boutput only\b|\brespond with only\b|\breply with only\b"
        r"|\banswer with only\b|\bonly the exact\b|\bnothing else\b"
        r"|\bno explanation\b|\bwithout explanation\b|\bno other text\b"
        r"|\bjust the (?:name|names|value|values|number|numbers|list|text|answer|title|titles)\b",
        re.IGNORECASE)
    _OUTPUT_ONLY_MIN_CHARS = 2


    def _answer_line_only(answer: str, question: str) -> str:
        if not answer or not _OUTPUT_ONLY_RE.search(question or ""):
            return answer
        for raw in answer.split("\n"):
            stripped = raw.strip()
            if not stripped:
                continue
            if stripped[0] in "#>":
                continue
            line = re.sub(r"^[*_`\s]+|[*_`\s]+$", "", stripped).strip()
            if not line:
                continue
            if line.startswith("|") or line.endswith(":"):
                continue
            if len(line) >= _OUTPUT_ONLY_MIN_CHARS:
                return line
        return answer


    _GLOSS_RE = re.compile(r"^(?P<a>[^()]{2,60}?)\s*\((?P<b>[^()]{2,60})\)$")


    def _verbatim_from_source(value: str, board: EvidenceBoard) -> str:
        v = (value or "").strip()
        m = _GLOSS_RE.match(v)
        if not m:
            return value
        texts = [r.get("text") or "" for r in board.rows if r.get("text")]
        if not texts:
            return value
        def seen(t: str) -> bool:
            return bool(t) and any(t in src for src in texts)
        if seen(v):
            return value
        a, b = m.group("a").strip(), m.group("b").strip()
        hits = [x for x in (b, a) if seen(x)]
        if len(hits) == 1:
            return hits[0]
        if len(hits) == 2:
            lo, hi = sorted(hits, key=len)
            if lo.lower() in hi.lower():
                return hi
        return value


    def _verbatim_structured(obj, board: EvidenceBoard, depth: int = 0):
        if depth > 6:
            return obj
        if isinstance(obj, str):
            return _verbatim_from_source(obj, board)
        if isinstance(obj, list):
            return [_verbatim_structured(x, board, depth + 1) for x in obj]
        if isinstance(obj, dict):
            return {k: _verbatim_structured(v, board, depth + 1) for k, v in obj.items()}
        return obj


    def _citations_for(answer: str, board: EvidenceBoard) -> list[CitationRef]:
        refs: list[CitationRef] = []
        spent = 0
        for n in _cited_numbers(answer, len(board.rows)):
            if len(refs) >= CITATION_CAP:
                break
            ref = board.ref_for(n)
            if ref is None:
                continue
            row = board.rows[n - 1]
            slices = getattr(ref, "slices", None)
            cost = (sum(max(0, s.end - s.start) for s in slices) if slices
                    else int(row.get("note_len") or 0))
            if spent + cost > EVIDENCE_CHAR_BUDGET:
                continue
            spent += cost
            refs.append(ref)
        return refs


    _VERIFY_MARK_RE = re.compile(r"\s*\((?:verify|unverified|uncertain)[^)]*\)", re.I)

    _TOOL_MARKUP_RE = re.compile(
        r"<\s*/?\s*tool_call|<\s*/?\s*(?:arg_key|arg_value|function_call|invoke)\b"
        r"|\bweb_search\s*[（(]\s*query|\bread_page\s*[（(]\s*url|\bsec_filing\s*[（(]\s*company",
        re.I)
    _STUB_ANSWER_RE = re.compile(r"^\s*(?:best-effort answer unavailable|no question provided)", re.I)
    _REFUSAL_ONLY_RE = re.compile(
        r"^\s*(?:i (?:cannot|can't|am unable|was unable)|unable to|sorry[,.]|"
        r"i don'?t have (?:enough|access))", re.I)
    _INTENT_NARRATION_RE = re.compile(
        r"^\s*(?:i (?:need|will|should|am going|'ll)\b|let me\b|first,? (?:i|let)\b|"
        r"i'?ll (?:search|look|start|begin|gather|check))", re.I)
    MIN_ANSWER_CHARS = 40
    MIN_CITED_ANSWER_CHARS = 12
    _CITE_MARK_RE = re.compile(r"\[[0-9]{1,3}\]")


    def _looks_like_tool_json(s: str) -> bool:
        return bool(re.match(r'\s*\{\s*"(?:name|tool|function)"\s*:', s))


    def _line_repetition_stall(body: str):
        lines = [ln.strip().lower() for ln in body.split("\n") if len(ln.strip()) > 25]
        if len(lines) >= 3:
            for ln in set(lines):
                if lines.count(ln) >= 3:
                    return True
            if len(set(lines)) * 2 > len(lines):
                return False
        return None


    def _sentence_repetition_stall(body: str) -> bool:
        sents = [s.strip().lower() for s in re.split(r"(?<=[.!?])\s+|\n+", body) if len(s.strip()) > 25]
        if len(sents) < 3:
            return False
        uniq = set(sents)
        if len(uniq) * 2 <= len(sents):
            return True
        for s in uniq:
            if sents.count(s) >= 3:
                return True
        return False


    def _is_degenerate_repetition(text: str) -> bool:
        body = text or ""
        line_verdict = _line_repetition_stall(body)
        if line_verdict is not None:
            return line_verdict
        return _sentence_repetition_stall(body)


    def _is_usable_answer(text: str) -> bool:
        s = _normalize_brackets(text).strip()
        if not s:
            return False
        if _TOOL_MARKUP_RE.search(s) or _looks_like_tool_json(s):
            return False
        if _STUB_ANSWER_RE.match(s) or _is_degenerate_repetition(s):
            return False
        cited = bool(_CITE_MARK_RE.search(s))
        if cited and len(s) >= MIN_CITED_ANSWER_CHARS:
            return True
        if len(s) < MIN_ANSWER_CHARS:
            return False
        if len(s) < 400 and (_REFUSAL_ONLY_RE.match(s) or _INTENT_NARRATION_RE.match(s)):
            return False
        return True


    _COMMIT_RULES = (
        "You are writing the FINAL ANSWER to a research question from evidence that "
        "has already been gathered. You have NO tools — never emit tool syntax. A "
        "judge compares your answer with a strong reference and credits only claims "
        "carrying an [n] citation to the numbered evidence.\n\n"
        "SHAPE: the first words are the answer entities themselves — no preamble, no "
        "remark about evidence quality. Then a short proof section: the candidate "
        "pool, each condition applied, one line per qualifier (cited) and one line "
        "per rejected member with its cited reason — every member gets its own "
        "line, never several swept into one clause. Reproduce figures and dates "
        "VERBATIM. Name ALL qualifying members — omitting one scores as wrong. "
        "Obey any literal formatting demand in the question — sort order, "
        "comma-separated, a requested count, 'without the word X' meaning delete "
        "that word — the shape is graded too. "
        "Never say what the evidence does not contain; commit to the best-supported "
        "answer you can defend."
    )

    _REPAIR_ORDER = (
        "Your last message was not a usable final answer (it contained tool-call "
        "markup, was empty, or was a refusal). Do NOT emit tool syntax as text. "
        "Write the FINAL ANSWER now as plain prose: first words are the answer "
        "entities themselves, every factual claim followed by its [n] citation, "
        "then the short proof section. Nothing else."
    )


    def _sanitize_draft(text: str) -> str:
        return _VERIFY_MARK_RE.sub("", text or "").strip()


    def _ledger_digest(board: EvidenceBoard, char_cap: int = 60000) -> str:
        parts: list[str] = []
        spent = 0
        for i, row in enumerate(board.rows, start=1):
            text = (row.get("preview") or "").strip()
            if not text:
                continue
            block = f"[{i}] {row.get('title') or ''} ({row.get('url') or ''})\n{text}"
            if spent + len(block) > char_cap:
                break
            spent += len(block)
            parts.append(block)
        return "\n\n".join(parts)


    _FURNITURE_RE = re.compile(
        r"^\s*(?:share|search|home|menu|subscribe|sign\s*in|log\s*in|newsletter|"
        r"advertisement|cookie|skip to|follow us|read more|related|tags?|categories?|"
        r"privacy|terms|contact|about us|navigation|toggle)\b", re.I)
    _SRC_FOOTNOTE_RE = re.compile(r"\[\s*\d{1,3}\s*\]")
    _MD_LINK_RE = re.compile(r"\]\(")
    _BARE_URL_RE = re.compile(r"(?<!\]\()https?://")
    _SENTENCEY_RE = re.compile(r"[.!?]\s|[.!?]$|\b(?:is|was|were|are|has|have|had|"
                               r"reported|announced|released|won|ranked|totall?ed)\b", re.I)


    def _informative_lead(preview: str, limit: int = 280) -> str:
        kept: list[str] = []
        broke = False
        for chunk in re.split(r"(?<=[.!?])\s+|\n+", _SRC_FOOTNOTE_RE.sub("", preview or "")):
            seg = " ".join(chunk.split())
            if len(seg) < 30 or len(seg) > 400:
                if kept:
                    broke = True
                    break
                continue
            if _SENTENCEY_RE.search(seg) is None:
                if kept:
                    broke = True
                    break
                continue
            if _FURNITURE_RE.match(seg) and not re.search(r"\d", seg):
                if kept:
                    broke = True
                    break
                continue
            if seg.startswith(("*", "|", "↑", "#")):
                if kept:
                    broke = True
                    break
                continue
            links = len(_MD_LINK_RE.findall(seg)) + len(_BARE_URL_RE.findall(seg))
            if links and links * 110 >= len(seg):
                if kept:
                    broke = True
                    break
                continue
            kept.append(seg)
            if sum(len(k) for k in kept) >= limit:
                break
        else:
            pass
        out = " ".join(kept).strip()
        if len(out) > limit:
            cut = out.rfind(" ", 0, limit)
            out = out[:cut if cut > 60 else limit].rstrip(" ,;:-")
        return out


    def _deterministic_answer(question: str, board: EvidenceBoard) -> str:
        rows = [(i, r) for i, r in enumerate(board.rows, start=1)
                if (r.get("preview") or "").strip()]
        if not rows:
            return ""
        out = ["Best-supported findings from the sources retrieved:"]
        picked = 0
        for i, r in rows:
            if picked >= 6:
                break
            lead = _informative_lead(r.get("preview") or "")
            if not lead:
                continue
            title = (r.get("title") or "").strip()
            out.append(f"- {title + ': ' if title else ''}{lead} [{i}]")
            picked += 1
        if picked == 0:
            for i, r in rows[:4]:
                lead = " ".join((r.get("preview") or "").split())[:280]
                if lead:
                    out.append(f"- {lead} [{i}]")
            if len(out) == 1:
                return ""
        return "\n".join(out)


    QUOTE_SYNTH_TIMEOUT_S = 42.0
    QUOTE_SYNTH_MIN_BUDGET_S = 30.0
    QUOTE_SYNTH_MIN_QUOTES = 2
    QUOTE_TABLE_CHARS = 1400


    def _quote_table(board: EvidenceBoard) -> str:
        parts = []
        for i, row in enumerate(board.rows, start=1):
            text = row.get("text") or ""
            for a, b in (row.get("retained") or []):
                excerpt = text[max(0, int(a)):int(b)][:QUOTE_TABLE_CHARS].strip()
                if excerpt:
                    parts.append(f"[{i}] {row.get('title') or row.get('url') or ''}\n{excerpt}")
        return "\n\n".join(parts)


    def _retained_count(board: EvidenceBoard) -> int:
        return sum(len(r.get("retained") or []) for r in board.rows)


    async def _write_from_digest(question: str, board: EvidenceBoard, deadline: float) -> str:
        left = deadline - monotonic()
        if left < 14.0:
            return ""
        digest = _ledger_digest(board)
        if not digest:
            return ""
        convo = [{"role": "system", "content": _COMMIT_RULES},
                 {"role": "user", "content": (
                     f"Question: {question}\n\nNumbered evidence you gathered (cite "
                     f"facts by these [n]):\n\n{digest}\n\n"
                     "Write the FINAL ANSWER now from this evidence. Plain prose, no "
                     "tool syntax. First words are the answer entities; every factual "
                     "claim carries its [n]; then the short proof section (pool, "
                     "conditions, qualifiers, exclusions).")}]
        async def _one(lane: str, model: str, budget: float) -> str:
            _p0 = _upstream(lane, model)
            payload = None
            for _p in ((_p0, None) if _p0 is not None else (None,)):
                try:
                    payload = await llm_chat(
                        provider=lane, model=model, messages=convo,
                        temperature=0.15, max_output_tokens=2600,
                        timeout=budget, thinking=_least_think(lane, model),
                        provider_extra=_p,
                    )
                    break
                except Exception:
                    if _p is None:
                        raise
                    continue
            _spend_note(payload)
            llm = getattr(payload, "llm", None)
            text = (getattr(llm, "raw_text", None) or "").strip()
            if not text:
                choices = getattr(llm, "choices", None) or []
                if choices:
                    c = getattr(choices[0].message, "content", None)
                    if isinstance(c, str):
                        text = c.strip()
            return text

        lanes = ((LLM_LANE_A, LOOP_MODEL_A), (LLM_LANE_B, LOOP_MODEL_B))
        for i, lane_model in enumerate(lanes):
            left = deadline - monotonic()
            if left < 14.0:
                return ""
            budget = min(RESCUE_TIMEOUT_S, left - DIGEST_TAIL_S)
            if i == 0:
                budget = min(budget, max(12.0, left - 14.0 - DIGEST_TAIL_S))
            if budget < 8.0:
                return ""
            try:
                text = await _one(lane_model[0], lane_model[1], budget)
            except Exception:
                continue
            if _is_usable_answer(text):
                return text
        return ""


    async def _knowledge_resort(question: str, deadline: float) -> str:
        left = deadline - monotonic()
        if left < 12.0:
            return ""
        try:
            return await _chat_simple(
                LLM_LANE_A, RESORT_MODEL,
                ("Expert researcher. Best definitive answer with concrete entities, "
                 "numbers, dates. Never refuse."),
                question, max_tokens=2600, timeout=min(45.0, left - 4.0))
        except Exception:
            return ""


    async def _schema_output(question: str, answer: str, schema, deadline: float) -> object | None:
        ask = ("Convert the answer to a JSON value valid under the schema. Output "
               "ONLY the JSON value.\n\n"
               f"Schema:\n{json.dumps(schema)}\n\nQuestion:\n{question}\n\n"
               f"Answer:\n{answer[:14000]}")
        for lane, model in ((LLM_LANE_A, SCHEMA_MODEL),
                            (LLM_LANE_A, RESORT_MODEL),
                            (LLM_LANE_B, LOOP_MODEL_B)):
            left = deadline - monotonic()
            if left < 12.0:
                break
            try:
                raw = await _chat_simple(lane, model,
                                         "You output strictly valid JSON.", ask,
                                         max_tokens=3400, timeout=min(45.0, left - 4.0))
                raw = re.sub(r"^```(?:json)?\s*|\s*```$", "", raw.strip(),
                             flags=re.I | re.M).strip()
                value = json.loads(raw)
                if _matches_schema_shape(value, schema):
                    return value
                if isinstance(value, dict) and len(value) == 1:
                    inner = list(value.values())[0]
                    if _matches_schema_shape(inner, schema):
                        return inner
            except Exception:
                continue
        return None


    def _schema_kind(schema) -> str:
        if not isinstance(schema, dict):
            return ""
        kind = schema.get("type")
        if isinstance(kind, list):
            kind = kind[0] if kind else None
        if kind is None:
            for key in ("anyOf", "oneOf", "allOf"):
                branch = schema.get(key)
                if isinstance(branch, list):
                    for sub in branch:
                        got = _schema_kind(sub)
                        if got:
                            return got
            if isinstance(schema.get("properties"), dict):
                return "object"
            if isinstance(schema.get("enum"), list):
                return "string"
            return ""
        return str(kind)


    def _matches_schema_shape(value, schema) -> bool:
        kind = _schema_kind(schema)
        if not kind:
            return True
        if kind == "array":
            return isinstance(value, list)
        if kind == "object":
            return isinstance(value, dict)
        if kind == "string":
            return isinstance(value, str)
        if kind == "integer":
            return isinstance(value, int) and not isinstance(value, bool)
        if kind == "number":
            return isinstance(value, (int, float)) and not isinstance(value, bool)
        if kind == "boolean":
            return isinstance(value, bool)
        if kind == "null":
            return value is None
        return True


    _NUM_IN_TEXT_RE = re.compile(r"-?\d[\d,]*(?:\.\d+)?")


    _DIGEST_LEAD_RE = re.compile(r"^\s*Best-supported findings|^\s*sources retrieved:", re.I)
    _DIGEST_NOISE_RE = re.compile(r"\[slice \d+:\d+\]|https?://\S+")
    _VALUE_MAX_CHARS = 90


    def _undigest_for_schema(basis: str) -> str:
        if not basis:
            return ""
        text = _DIGEST_NOISE_RE.sub(" ", basis)
        out = []
        for raw in text.split("\n"):
            line = raw.strip().lstrip("-*• ").strip()
            if not line or _DIGEST_LEAD_RE.match(line):
                continue
            if ":" in line:
                head, _, tail = line.partition(":")
                line = tail.strip() if 0 < len(tail.strip()) <= _VALUE_MAX_CHARS else head.strip()
            if not line or len(line) > _VALUE_MAX_CHARS:
                continue
            if line.count(" ") > 8:
                continue
            if line not in out:
                out.append(line)
            if len(out) >= 6:
                break
        return "\n".join(out)


    def _coerce_enum_value(answer: str, enum: list):
        low = (answer or "").lower()
        for opt in enum:
            if isinstance(opt, str) and re.search(r"\b" + re.escape(opt.lower()) + r"\b", low):
                return opt
        return enum[0]


    def _coerce_union_branch(answer: str, schema, depth: int):
        for key in ("anyOf", "oneOf", "allOf"):
            branch = schema.get(key)
            if isinstance(branch, list) and branch:
                for sub in branch:
                    if isinstance(sub, dict) and sub.get("type") != "null":
                        return True, _coerce_to_schema(answer, sub, depth + 1)
        return False, None


    def _coerce_array_value(answer: str, schema, depth: int):
        items = schema.get("items") or {}
        parts = [p.strip(" -*\t") for p in re.split(r"[\n;]|,(?![^(]*\))", answer or "")]
        parts = [p[:400] for p in parts if p][:20]
        if not parts:
            parts = [answer[:400]]
        return [_coerce_to_schema(p, items, depth + 1) for p in parts]


    def _coerce_object_value(answer: str, schema, depth: int):
        props = schema.get("properties") or {}
        required = schema.get("required") or list(props.keys())
        out = {}
        for key in required:
            out[key] = _coerce_to_schema(answer, props.get(key) or {}, depth + 1)
        return out


    def _coerce_numeric_value(answer: str, kind: str):
        found = _NUM_IN_TEXT_RE.search(_CITE_NUM_RE.sub(" ", answer or ""))
        if found is None:
            return 0
        val = found.group(0).replace(",", "")
        try:
            return int(val) if kind == "integer" else float(val)
        except Exception:
            return 0


    def _coerce_to_schema(answer: str, schema, depth: int = 0):
        if depth > 4 or not isinstance(schema, dict):
            return answer[:400]
        enum = schema.get("enum")
        if isinstance(enum, list) and enum:
            return _coerce_enum_value(answer, enum)
        kind = _schema_kind(schema)
        if not kind:
            found, coerced = _coerce_union_branch(answer, schema, depth)
            if found:
                return coerced
            kind = "string"
        if kind == "array":
            return _coerce_array_value(answer, schema, depth)
        if kind == "object":
            return _coerce_object_value(answer, schema, depth)
        if kind in ("number", "integer"):
            return _coerce_numeric_value(answer, kind)
        if kind == "boolean":
            return not re.match(r"\s*(no\b|false\b|none\b)", (answer or ""), re.I)
        return (answer or "")[:400]


    _NARRATION_LEAD_RE = re.compile(
        r"^\s*(?:based on (?:my|the)\b|now (?:i|that i)\b|i (?:now )?(?:have|was|am|need|will|can)\b|"
        r"i(?:'ll|'ve|'m)\b|let me\b|let's\b|first,? i\b|having (?:now )?\w+\b|"
        r"okay\b|alright\b|to answer this\b|my research\b)", re.IGNORECASE)
    _ABBREV_TAIL_RE = re.compile(r"(?:\b[A-Z]|\b(?:Inc|Ltd|Co|No|vs|St|Dr|Mr|Ms|Mt|Jr|Sr|etc|e\.g|i\.e))\.$")


    def _strip_lead_narration(text: str) -> str:
        t = (text or "").strip()
        if not t:
            return t
        for _ in range(2):
            parts = re.split(r"(?<=[.!?])\s+", t, maxsplit=1)
            if len(parts) != 2:
                break
            head, rest = parts[0], parts[1].strip()
            if _CITE_NUM_RE.search(head):
                break
            if _NARRATION_LEAD_RE.match(head) is None:
                break
            if len(head.split()) < 4 or _ABBREV_TAIL_RE.search(head) is not None:
                break
            if len(rest) < 120 or _CITE_NUM_RE.search(rest) is None:
                break
            t = rest
        return t


    def _cap(text: str) -> str:
        t = (text or "").strip()
        if len(t) > ANSWER_CHAR_CAP:
            return t[:ANSWER_CHAR_CAP - 16] + " …"
        return t


    async def _hx55_base_query(query: Query) -> Response:
        question = (query.text or "").strip()
        if not question:
            return _empty_question_response()
        try:
            return await ResearchCoordinator(query, question).execute()
        except Exception:
            return _unavailable_response(question, 500)


    class ResearchCoordinator:
        def __init__(self, query: Query, question: str) -> None:
            self.query = query
            self.question = question
            self.deadline = 0.0
            self.draft = ""
            self.brief = ""
            self.board = None
            self.answer = ""
            self.messages: list[dict] = []
            self.citations: list = []
            self.text = ""

        async def execute(self) -> Response:
            self.deadline = monotonic() + WALL_BUDGET_S
            await self._note_session_budget()
            await self._optional_knowledge_brief()
            self.board = EvidenceBoard()
            self.answer = ""
            self.messages = []
            await self._run_research_loop()
            await self._optional_verify()
            await self._optional_format()
            await self._optional_units()
            await self._rescue_ladder()
            self._collect_citations()
            self._polish()
            if self.query.output_schema is not None:
                return await self._emit_structured()
            return self._emit_prose()

        async def _note_session_budget(self) -> None:
            try:
                info = await tooling_info(timeout=10.0)
                _spend_note(info)
            except Exception:
                pass

        async def _optional_knowledge_brief(self) -> None:
            try:
                if _spend_left() >= BRIEF_MIN_USD and _wall_remaining(self.deadline) > _BRIEF_REMAINING_FLOOR_S:
                    self.draft, self.brief = await _knowledge_brief(self.question)
            except Exception:
                self.brief = ""

        async def _run_research_loop(self) -> None:
            try:
                _capability_hint = _capability_signal_boost(self.question)
                if _capability_hint:
                    self.brief = (self.brief + "\n\n" + _capability_hint) if self.brief else _capability_hint
                self.answer, self.messages = await _execute_research_loop(
                    self.question, self.brief, self.board, self.deadline, MAX_TURNS)
            except Exception:
                self.answer = ""

        async def _adopt_usable(self, should_run, producer) -> None:
            try:
                if should_run():
                    patched = await producer()
                    if _is_usable_answer(patched):
                        self.answer = patched
            except Exception:
                pass

        async def _optional_verify(self) -> None:
            await self._adopt_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _wall_remaining(self.deadline) > _AUDIT_REMAINING_FLOOR_S
                         and _spend_left() >= AUDIT_MIN_USD),
                lambda: _verify_and_refine(self.question, self.answer, self.messages,
                                           self.board, self.deadline),
            )

        async def _optional_format(self) -> None:
            await self._adopt_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _wall_remaining(self.deadline) > _FORMAT_REMAINING_FLOOR_S),
                lambda: _format_repair(self.question, self.answer, self.messages,
                                       self.board, self.deadline),
            )

        async def _optional_units(self) -> None:
            await self._adopt_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _wall_remaining(self.deadline) > _UNIT_REMAINING_FLOOR_S
                         and _spend_left() >= AUDIT_MIN_USD),
                lambda: _unit_repair(self.question, self.answer, self.messages,
                                     self.board, self.deadline),
            )

        async def _rescue_ladder(self) -> None:
            if not _is_usable_answer(self.answer) and self.board.rows:
                try:
                    rescued = await _write_from_digest(self.question, self.board, self.deadline)
                    if _is_usable_answer(rescued):
                        self.answer = rescued
                except Exception:
                    pass
            if not _is_usable_answer(self.answer) and self.board.rows:
                det = _deterministic_answer(self.question, self.board)
                if _is_usable_answer(det):
                    self.answer = det
            if not _is_usable_answer(self.answer):
                fallback = _sanitize_draft(self.draft) or await _knowledge_resort(self.question, self.deadline)
                if _is_usable_answer(fallback):
                    self.answer = fallback

        def _collect_citations(self) -> None:
            try:
                self.citations = _citations_for(self.answer, self.board)
            except Exception:
                self.citations = []

        def _polish(self) -> None:
            self.answer = _normalize_brackets(self.answer)
            self.answer = _strip_lead_narration(self.answer)
            self.answer = _answer_line_only(self.answer, self.question)
            self.text = _cap(self.answer) or f"{_UNAVAILABLE_PREFIX}{self.question[:400]}"

        async def _emit_structured(self) -> Response:
            query = self.query
            question = self.question
            answer = self.answer
            board = self.board
            deadline = self.deadline
            citations = self.citations
            structured = None
            try:
                structured = await _schema_output(question, answer, query.output_schema, deadline)
            except Exception:
                structured = None
            if structured is not None:
                try:
                    structured = _verbatim_structured(structured, board)
                except Exception:
                    pass
                try:
                    return Response(output=structured, citations=citations or None)
                except Exception:
                    structured = None
            basis = answer if _is_usable_answer(answer) else ""
            if not basis:
                basis = _deterministic_answer(question, board)
            if not basis or _STUB_ANSWER_RE.match(basis.strip()):
                basis = question[:400]
            if basis is not answer:
                try:
                    salvaged = await _schema_output(question, basis, query.output_schema,
                                                    deadline)
                except Exception:
                    salvaged = None
                if salvaged is not None:
                    try:
                        return Response(output=salvaged, citations=citations or None)
                    except Exception:
                        pass
            if basis is not answer:
                cleaned = _undigest_for_schema(basis)
                basis = cleaned if cleaned else ""
            try:
                forced = _coerce_to_schema(_cap(basis), query.output_schema)
                return Response(output=forced, citations=citations or None)
            except Exception:
                try:
                    return Response(output=_cap(basis)[:2000],
                                    citations=citations or None)
                except Exception:
                    pass
            return self._emit_prose()

        def _emit_prose(self) -> Response:
            try:
                return Response(text=self.text, citations=self.citations or None)
            except Exception:
                return Response(text=self.text)

    _HX55_MODEL = "openai/gpt-oss-120b"
    _HX55_MIN_SPEND_USD = 0.04
    _HX55_SKIP_IF_BASE_ELAPSED_S = 150.0
    _HX55_WINDOW_MAX_S = 38.0
    _HX55_ROUTE_TIMEOUT_S = 12.0
    _HX55_FETCH_TIMEOUT_S = 14.0
    _HX55_JUDGE_TIMEOUT_S = 12.0
    _HX55_ROUTE_RESULTS = 3
    _HX55_MAX_URLS = 3
    _HX55_MAX_REFS = 5
    _HX55_SLICE_CHARS = 500
    _HX55_ROUTE_SYSTEM = """You are a source-routing analyst. Given a research
    question and draft answer, identify source types that should be fetched in full:
    official records, primary documents, standards, papers, or first-party pages.
    Return JSON only: {"routes":[{"focus":str,"query":str,"preferred_domains":[str]}]}.
    Use at most four precise queries. Search results are only routes; their snippets
    will never be cited."""
    _HX55_BIND_SYSTEM = """You select fetched full pages that are relevant to a
    research answer. A page may be selected only if its supplied text directly bears
    on the question. Return JSON only: {"keep":[integer], "reason":str}. Do not
    infer facts and do not select a result merely because its URL looks authoritative."""


    class _Hx55CascadeEvidence:


        def __init__(self, question: str, answer: str):
            self.question = question
            self.answer = answer
            self.routes: list[dict] = []
            self.urls: list[str] = []
            self.pages: list[dict] = []

        def set_routes(self, rows: list[dict]) -> None:
            self.routes = rows[:_HX55_MAX_URLS]

        def add_url(self, url: str) -> None:
            clean = url.strip()
            if clean.startswith(("http://", "https://")) and clean not in self.urls:
                self.urls.append(clean)

        def add_page(self, url: str, payload) -> None:
            text = _hx55_page_text(payload)
            receipt = str(getattr(payload, "receipt_id", "") or "")
            result_id = getattr(payload, "result_id", None)
            if receipt and isinstance(result_id, str) and result_id and text:
                self.pages.append({"url": url, "receipt": receipt, "result_id": result_id,
                                   "text": text})

        def render_pages(self) -> str:
            return "\n\n".join(
                f"[{index}] URL: {page['url']}\n{page['text'][:1800]}"
                for index, page in enumerate(self.pages))

        def refs(self, selected: list[int]) -> list:
            out: list = []
            for index in selected:
                if not 0 <= index < len(self.pages):
                    continue
                page = self.pages[index]
                try:
                    out.append(CitationRef(
                        receipt_id=page["receipt"], result_id=page["result_id"],
                        slices=[CitationSlice(start=0, end=min(_HX55_SLICE_CHARS,
                                                              len(page["text"])))]))
                except Exception:
                    continue
            return out

        async def collect_refs(self):
            self.set_routes(await _hx55_routes(self.question, self.answer))
            if not self.routes:
                return None
            await _hx55_search_urls(self)
            await _hx55_fetch_pages(self)
            return self.refs(await _hx55_choose(self))


    def _hx55_json(raw: str | None) -> dict:
        cleaned = re.sub(r"^```(?:json)?\s*|\s*```$", "", (raw or "").strip(),
                         flags=re.I | re.M).strip()
        try:
            value = json.loads(cleaned)
        except Exception:
            left, right = cleaned.find("{"), cleaned.rfind("}")
            if left < 0 or right <= left:
                return {}
            try:
                value = json.loads(cleaned[left:right + 1])
            except Exception:
                return {}
        return value if isinstance(value, dict) else {}


    def _hx55_text(payload) -> str:
        for holder in (getattr(payload, "llm", None), getattr(payload, "response", None)):
            value = getattr(holder, "raw_text", None) if holder is not None else None
            if isinstance(value, str) and value.strip():
                return value.strip()
        choices = getattr(getattr(payload, "llm", None), "choices", None) or []
        content = getattr(getattr(choices[0], "message", None), "content", None) if choices else None
        return content.strip() if isinstance(content, str) else ""


    def _hx55_page_text(payload) -> str:
        value = (getattr(payload, "text", None) or getattr(payload, "content", None)
                 or getattr(payload, "note", None) or "")
        if isinstance(value, bytes):
            value = value.decode("utf-8", "ignore")
        return str(value).strip()


    async def _hx55_ask(system: str, user: str, tokens: int, timeout: float) -> str:
        upstream = _upstream(LLM_LANE_A, _HX55_MODEL)
        attempts = [upstream] if upstream is not None else [None]
        if upstream is not None:
            attempts.append(None)
        for extra in attempts:
            try:
                payload = await llm_chat(
                    provider=LLM_LANE_A, model=_HX55_MODEL,
                    messages=[{"role": "system", "content": system},
                              {"role": "user", "content": user}],
                    temperature=0.0, max_output_tokens=tokens, timeout=timeout,
                    thinking=_least_think(LLM_LANE_A, _HX55_MODEL), provider_extra=extra)
                _spend_note(payload)
                return _hx55_text(payload)
            except Exception:
                continue
        return ""


    async def _hx55_routes(question: str, answer: str) -> list[dict]:
        raw = await _hx55_ask(_HX55_ROUTE_SYSTEM,
                              f"Question:\n{question[:3500]}\n\nDraft:\n{answer[:7000]}",
                              900, _HX55_JUDGE_TIMEOUT_S)
        rows: list[dict] = []
        for item in _hx55_json(raw).get("routes") or []:
            if not isinstance(item, dict):
                continue
            probe = str(item.get("query") or "").strip()
            if probe:
                rows.append({"query": probe[:360], "focus": str(item.get("focus") or "")[:180]})
        return rows[:_HX55_MAX_URLS]


    async def _hx55_search_urls(evidence: _Hx55CascadeEvidence) -> None:
        for route in evidence.routes:
            try:
                payload = await search_web(route["query"], provider=SEARCH_PROVIDER,
                                           num=_HX55_ROUTE_RESULTS, timeout=_HX55_ROUTE_TIMEOUT_S)
                _spend_note(payload)
            except Exception:
                continue
            for result in list(getattr(payload, "results", None) or []):
                evidence.add_url(str(getattr(result, "url", "") or ""))
                if len(evidence.urls) >= _HX55_MAX_URLS:
                    return


    async def _hx55_fetch_pages(evidence: _Hx55CascadeEvidence) -> None:
        payloads = await asyncio.gather(*[
            fetch_page(url, provider=SEARCH_PROVIDER, timeout=_HX55_FETCH_TIMEOUT_S)
            for url in evidence.urls[:_HX55_MAX_URLS]], return_exceptions=True)
        for url, payload in zip(evidence.urls, payloads):
            if isinstance(payload, Exception):
                continue
            _spend_note(payload)
            evidence.add_page(url, payload)


    async def _hx55_choose(evidence: _Hx55CascadeEvidence) -> list[int]:
        if not evidence.pages:
            return []
        raw = await _hx55_ask(_HX55_BIND_SYSTEM,
                              f"Question:\n{evidence.question[:3000]}\n\n"
                              f"Draft:\n{evidence.answer[:5000]}\n\nFetched pages:\n"
                              f"{evidence.render_pages()}",
                              500, _HX55_JUDGE_TIMEOUT_S)
        indices: list[int] = []
        for value in _hx55_json(raw).get("keep") or []:
            try:
                index = int(value)
            except Exception:
                continue
            if 0 <= index < len(evidence.pages) and index not in indices:
                indices.append(index)
        return indices[:_HX55_MAX_REFS]


    def _hx55_merge(response: Response, refs: list) -> Response:
        existing = list(getattr(response, "citations", None) or [])
        known = {(getattr(ref, "receipt_id", None), getattr(ref, "result_id", None))
                 for ref in existing}
        for ref in refs:
            key = (getattr(ref, "receipt_id", None), getattr(ref, "result_id", None))
            if key not in known:
                known.add(key)
                existing.append(ref)
        try:
            return response.model_copy(update={"citations": existing})
        except Exception:
            return response


    async def _hx55_stage(question: str, response: Response) -> Response:
        evidence = _Hx55CascadeEvidence(question, (getattr(response, "text", None) or "").strip())
        refs = await evidence.collect_refs()
        if refs is None:
            return response
        return _hx55_merge(response, refs)


    async def query(query: Query) -> Response:
        started = monotonic()
        response = await _hx55_base_query(query)
        try:
            if getattr(query, "output_schema", None) is not None or getattr(response, "output", None) is not None:
                return response
            if not _is_usable_answer(getattr(response, "text", None) or ""):
                return response
            if monotonic() - started > _HX55_SKIP_IF_BASE_ELAPSED_S or _spend_left() < _HX55_MIN_SPEND_USD:
                return response
            timeout = min(_HX55_WINDOW_MAX_S, max(8.0, WALL_BUDGET_S - (monotonic() - started) - 8.0))
            return await asyncio.wait_for(_hx55_stage((query.text or "").strip(), response), timeout=timeout)
        except Exception:
            return response

    return query

_zephyr_notary_query_entry = _compose_zephyr_notary_entry()


def _compose_basil_surveyor_entry():


    import asyncio
    import json
    import re
    from time import monotonic

    from harnyx_miner_sdk.api import fetch_page, llm_chat, search_web, tooling_info
    from harnyx_miner_sdk.decorators import entrypoint
    from harnyx_miner_sdk.query import CitationRef, CitationSlice, Query, Response

    VERSION = "hx66-425-zw1"

    LLM_LANE_A = "openrouter"
    LLM_LANE_B = "openrouter"
    LOOP_MODEL_A = "z-ai/glm-5.2"
    LOOP_MODEL_B = "z-ai/glm-5"
    AUDIT_MODEL = "openai/gpt-oss-120b"
    SCHEMA_MODEL = "openai/gpt-oss-120b"
    RESORT_MODEL = "deepseek/deepseek-v3.2"
    SEARCH_PROVIDER = "parallel"

    WALL_BUDGET_S = 266.0
    BRIEF_TIMEOUT_S = 50.0
    TURN_TIMEOUT_S = 75.0
    LANE_B_MAX_PAYLOAD_CHARS = 144000
    AUDIT_TIMEOUT_S = 28.0
    SEARCH_TIMEOUT_S = 18.0
    FETCH_TIMEOUT_S = 16.0
    WRAPUP_AT_S = 90.0
    MIN_TAIL_S = 8.0
    MAX_TURNS = 15
    AUDIT_EXTRA_TURNS = 2
    ANSWER_REPAIR_TURNS = 2
    RESCUE_TIMEOUT_S = 55.0
    DIGEST_TAIL_S = 14.0

    SEARCH_EXCERPT_CHARS = 550
    _LEDGER_TEXT_CAP = 400_000
    PAGE_GREP_WINDOW = 700
    PAGE_GREP_MAX_HITS = 6
    PAGE_READ_MAX_CHARS = 12_000

    RETAIN_MARGIN_CHARS = 260
    RETAIN_MAX_PER_ROW = 6
    RETAIN_MIN_QUOTE = 12
    FETCH_HEAD_CHARS = 3000
    FETCH_WINDOW_CHARS = 3600

    CITATION_MIN_SPAN_CHARS = 6000
    CITATION_MAX_REF_CHARS = 14_000
    FETCH_WINDOWS_PER_PAGE = 3
    FETCH_PLAIN_CHARS = 6500
    ANSWER_CHAR_CAP = 60000
    CITATION_CAP = 24
    EVIDENCE_CHAR_BUDGET = 105_000

    BRIEF_MIN_USD = 0.03
    AUDIT_MIN_USD = 0.05
    WRAPUP_MIN_USD = 0.02

    _LOOP_CALL_CAP = 8
    _BRIEF_TIME_FLOOR_S = 120.0
    _AUDIT_TIME_FLOOR_S = 75.0
    _WINDOW_TIME_FLOOR_S = 65.0
    _CORROB_TIME_FLOOR_S = 75.0
    _REPAIR_SLACK_S = 10.0
    _FANOUT_FLOOR_S = 5.0
    _FANOUT_PAD_S = 6.0
    _SKIPPED_TOOL_BODY = (
        "# skipped: per-turn tool budget reached — re-issue next turn if still needed")
    _TIMEOUT_TOOL_BODY = "# tool timed out — use what you already have"
    _CRASH_TOOL_PREFIX = "# tool crashed: "
    _BLANK_QUESTION = "No question provided."
    _BEST_EFFORT_PREFIX = "Best-effort answer unavailable for: "

    _SPEND = {"left": None}


    def _spend_note(payload) -> None:
        budget = getattr(payload, "budget", None)
        left = getattr(budget, "session_remaining_budget_usd", None)
        if isinstance(left, (int, float)):
            _SPEND["left"] = float(left)


    def _spend_left() -> float:
        left = _SPEND["left"]
        if isinstance(left, (int, float)):
            return float(left)
        return 1.0


    def _clock_left(deadline: float) -> float:
        return deadline - monotonic()


    def _blank_question_reply() -> Response:
        return Response(text=_BLANK_QUESTION)


    def _best_effort_reply(question: str, cap: int) -> Response:
        return Response(text=f"{_BEST_EFFORT_PREFIX}{question[:cap]}")


    LOOP_TOOLS = [
        {
            "type": "function",
            "function": {
                "name": "web_search",
                "description": ("Web search. Returns numbered results, each with title, "
                                "url and excerpt."),
                "parameters": {
                    "type": "object",
                    "properties": {"query": {"type": "string",
                                             "description": "the search query"}},
                    "required": ["query"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "sec_filing",
                "description": ("Resolve a company's SEC filing to its primary document "
                                "URL on sec.gov (exact form + year, from EDGAR's own "
                                "index). Use for questions about a specific filing "
                                "(10-K, 10-Q, 8-K, DEF 14A…), then read_page the "
                                "returned URL with a focus hint for the Item/section."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "company": {"type": "string",
                                    "description": "company name or ticker, e.g. 'Apple' or 'AAPL'"},
                        "form": {"type": "string",
                                 "description": "filing form, e.g. '10-K', '10-Q', '8-K', 'DEF 14A'"},
                        "year": {"type": "string",
                                 "description": "optional report (fiscal) year, e.g. '2019' (omit for latest)"},
                    },
                    "required": ["company", "form"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "read_page",
                "description": ("Fetch a URL and return its main text. Large pages show "
                                "the head plus the few regions most relevant to the "
                                "question; pass a focus hint to steer which regions."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string", "description": "URL to fetch"},
                        "focus": {"type": "string",
                                  "description": ("optional phrase to locate inside the "
                                                  "page (section name, table label, "
                                                  "entity)")},
                    },
                    "required": ["url"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "page_grep",
                "description": ("Search INSIDE a page you already fetched, by regex or "
                                "literal text, and get every match with its surrounding "
                                "context and character offset. Use this when read_page "
                                "showed you the head of a long page but the value you "
                                "need is deeper in it -- do not re-fetch, grep it."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string",
                                "description": "URL of a page already fetched this run"},
                        "pattern": {"type": "string",
                                    "description": ("regex or literal string to find, e.g. "
                                                    "a city name, a year, a column label")},
                    },
                    "required": ["url", "pattern"],
                },
            },
        },
        {
            "type": "function",
            "function": {
                "name": "page_read",
                "description": ("Read an arbitrary character range of a page you already "
                                "fetched. Use the offsets page_grep reports to read the "
                                "full table or section around a match."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "url": {"type": "string", "description": "URL already fetched"},
                        "offset": {"type": "integer", "description": "start character offset"},
                        "length": {"type": "integer",
                                   "description": "how many characters to read (max 12000)"},
                    },
                    "required": ["url", "offset"],
                },
            },
        },
    {
            "type": "function",
            "function": {
                "name": "retain_evidence",
                "description": ("Keep the exact source text that proves a claim you are "
                                "about to make. Pass the result number and the verbatim "
                                "quote from it. Do this the moment you find a decisive "
                                "value -- the judge only credits claims whose citation "
                                "contains the supporting text, and this is how that text "
                                "gets into your citation. Use it for the QUESTION'S "
                                "PREMISES as well as your answer: every entity, work, "
                                "date or figure the question names should end up with a "
                                "retained quote confirming it."),
                "parameters": {
                    "type": "object",
                    "properties": {
                        "source": {"type": "string",
                                   "description": "result number to quote from, e.g. 3"},
                        "quote": {"type": "string",
                                  "description": ("verbatim text copied from that result "
                                                  "that states the fact")},
                    },
                    "required": ["source", "quote"],
                },
            },
        },
    ]

    LOOP_RULES = (
        "You are a research agent answering a hard multi-part factual question. A "
        "judge compares your answer head-to-head with a strong reference and only "
        "credits claims that carry a citation to a tool result that states them.\n\n"
        "PREFER THE PRIMARY SOURCE: when two sources state the same fact, cite the "
        "one that ORIGINATES it -- the agency, registry, filing, official statistics "
        "release or the organisation's own page -- not an encyclopedia or aggregator "
        "repeating it. Measured verbatim on a task where both answers were factually "
        "correct: \"Answer 1 is preferred for using primary sources\" (it cited NARA "
        "where we cited Wikipedia) -- a full point lost on every run. Use the "
        "encyclopedia to FIND the primary source, then fetch and cite that.\n\n"
        "QUOTE WHAT PROVES IT: the judge credits a claim only when your citation "
        "CONTAINS the source text stating it. The moment you read a decisive value, "
        "call retain_evidence(source, quote) with the exact words from that result. "
        "Do this for every condition you test and every figure you report -- an "
        "answer whose citations do not carry its numbers loses to one that does, "
        "even when both answers are identical.\n"
        "ALSO QUOTE THE QUESTION'S PREMISES, not only your answer. Every entity, "
        "work, date or figure the question NAMES is a claim the judge expects "
        "traceable: the film it says someone directed, the article it points at, "
        "the year it fixes, the people it lists. You lose to an otherwise identical "
        "answer that cited those too -- measured verbatim: \"does not provide a "
        "citation for 'Everyone Says I Love You'... Answer 1 is more thorough in "
        "its traceability to all parts of the prompt's context\". Retain a quote "
        "for each named premise as you confirm it, even when it is background you "
        "already believed.\n\n"
        "READ DEEP, DO NOT RE-FETCH: read_page shows the head plus a few regions of "
        "a long page. If the value you need is not in what you were shown, call "
        "page_grep(url, pattern) to find it anywhere in that page and page_read to "
        "open the region around a reported offset. Grepping a page you already have "
        "costs nothing and beats another search.\n\n"
        "METHOD: think in constraints and candidates. Recall what you already know "
        "to form the candidate pool, then use web_search/read_page to verify every "
        "load-bearing fact (names, figures, dates, rankings) before asserting it. "
        "Work every candidate through every stated condition; one search per fact "
        "beats one broad search. TWO DISTINCT SUB-QUESTIONS: if the question asks two "
        "separate things, answer BOTH substantively — a partial answer covering both "
        "sides outscores a complete answer to only one. BATCH YOUR LOOKUPS: independent facts (each "
        "candidate's score, each entity's figure) should be requested as SEVERAL "
        "tool calls in the SAME turn — they run in parallel, so a 6-candidate "
        "sweep costs one turn, not six. TABLE CARE: when reading a table, respect its "
        "qualifier columns (Owned vs Leased, the exact year, the exact segment) — "
        "count or compare only rows matching EVERY stated qualifier, and quote the "
        "row values you used. For a named source (Box Office Mojo, a 10-K, "
        "Nielsen), fetch THAT page — for SEC filings, use the sec_filing tool to "
        "resolve the exact primary document from EDGAR's own index, then read_page "
        "it with a focus hint for the Item/section.\n\n"
        "CITE EVERYTHING: put [n] (the tool-result number) immediately after the "
        "SENTENCE carrying each claim — not pooled at the end of a paragraph. Every "
        "sentence asserting a number, date, proper noun or causal link needs its own "
        "[n], for the entities you rule OUT as well as those you include. An uncited "
        "specific reads as invented. Cite only results that actually state the claim, "
        "and prefer the most AUTHORITATIVE one that does: the official database/"
        "filing/statistics page over an aggregator, blog, or retrospective article. "
        "CITE THE HARD CONDITION, NOT JUST THE POOL: every stated condition needs "
        "evidence of its own, and the one hardest to verify is the one the grader "
        "checks. Citations that establish only the candidate pool leave the actual "
        "filter unsupported — a right answer whose decisive condition is uncited "
        "loses to a weaker answer that proves it.\n\n"
        "SOURCE CONFIDENCE: when the question NAMES a source you could not reach but "
        "other authoritative evidence establishes the same facts, state those facts "
        "plainly and confidently with their [n], and treat the other sources as "
        "corroboration. Do not open with, dwell on, or append a note that the named "
        "source was unavailable — reserve missing-source language for a FACT that is "
        "genuinely absent everywhere, never for a missing source LABEL.\n\n"
        "SELF-CONSISTENCY: before you finish, check that the opening names exactly "
        "the entities your own cited sentences support. If the body establishes a "
        "different answer than the opening claims, rewrite the opening to match the "
        "evidence — never leave a weaker fallback in the lead.\n\n"
        "ANSWER SHAPE: sentence one IS the answer — the exact entities/values/list "
        "asked for, in the requested format. Never open with 'Based on…', 'From my "
        "research…', 'I can provide a partial answer', or any preamble — start with "
        "the answer entities themselves. ANSWER THE ASKED KIND: if the question asks "
        "which SERIES, name the series (not the people in it); which FILM, the film "
        "(not its director); which COUNTRY, the country. "
        "THE POOL IS THE WHOLE NAMED CLASS, NOT THE SURVIVORS: build it from the "
        "broadest set the question ranges over — every member of that class, not the "
        "ones you already believe qualify — then apply the conditions one at a time and "
        "show who each one eliminates. Never pre-filter to the members that already "
        "pass and present those as the pool — an answer whose pool contains only "
        "qualifiers proves nothing about the sweep, which is how a correct answer "
        "still scores zero. List members that fail on the FIRST condition too. "
        "Then: the candidate pool, each condition applied, and ONE LINE PER POOL MEMBER — "
        "a line for every qualifier with its qualifying attribute cited, AND a line "
        "for every candidate you rule out with its cited failing condition. Never "
        "compress several rejects into one clause ('X, Y and Z never won [n]'): each "
        "rejected member gets its own line and its own [n], even when the pool runs "
        "to a dozen members. A batched exclusion reads as a pool you never checked. "
        "Two later instructions may relax this — one when time runs short, one "
        "when the pool is too large to list in full — and nothing else does. "
        "If you cannot settle a member's condition, KEEP it among the qualifiers — a "
        "wrongly-dropped qualifier costs as much as a wrong answer — and give its "
        "line the strongest fact you did verify. Never add a note about what you "
        "could not check. "
        "OUTPUT DIRECTIVES ARE LITERAL: obey formatting instructions mechanically. "
        "Decide first whether a phrase constrains the OUTPUT or selects the "
        "ENTITIES: 'list them without the word \"X\"' shapes what you print, so "
        "DELETE X from each name; 'whose title does not contain \"X\"' / 'titles "
        "without the word X' is a condition on the pool, so keep only members that "
        "lack it. When the phrase governs how to print an already-chosen set, the "
        "deletion reading applies — it is not a filter. 'in alphabetical/chronological order' means sort the final "
        "list; 'comma-separated' means join with commas; a requested count means "
        "emit the number. These govern the ANSWER LINE — give it in exactly the "
        "requested shape, then still add the proof section below it; the shape "
        "directive is never a reason to omit the proof. COPY SOURCE VALUES "
        "VERBATIM: when the question names a source, every name, label and value in "
        "the answer must be the exact string that source prints -- never add a "
        "familiar alternative in parentheses, never anglicise a transliteration. "
        "'Makkah' is the answer; 'Mecca (Makkah)' is a wrong answer. "
        "ONE EXCEPTION, and it is "
        "absolute: if the question says to output ONLY the answer (\'output only\', "
        "\'respond with only\', \'nothing else\', \'no explanation\'), emit the answer "
        "line as the BARE requested text — no [n] markers on it, nothing else on "
        "that line: a trailing [3] makes the text inexact and fails the "
        "instruction. Still write the PROOF section BELOW it carrying its [n] "
        "markers. Only the answer line is shipped, but the citations are "
        "harvested from the proof first, and an uncited answer scores zero. "
        "Obeying that "
        "instruction IS the task. When an ORDER is demanded, "
        "the ANSWER LINE itself must be sorted — not merely the table under it. "
        "Print the sort key beside each item (the year, figure or date you sorted "
        "on) and check every adjacent pair before you finish: one member out of "
        "sequence fails the whole answer even when the set is exactly right. "
        "COMPUTED ANSWERS: if the answer is a mean, total, rank or count derived "
        "from several figures, pull every input into one explicit list first, then "
        "compute — and show the arithmetic so the number is checkable. Never report "
        "a derived number you did not visibly compute from listed inputs. "
        "ROUNDED FIGURE = WRONG SOURCE: a decisive number that reads as rounded — "
        "trailing zeros where the measuring body publishes exact digits, "
        "'X.Y thousand/million', 'about'/'approximately', "
        "or a value lifted from a chart label — came from an aggregator that "
        "publishes summaries, not from the body that measured it. Do NOT commit it. "
        "Search again for the exact figure from the source the question NAMES (or "
        "the outlet that reports that source's own numbers) and answer with the full "
        "precision it publishes, digit for digit. Quote the rounded value only as "
        "corroboration after the exact one. This is a RETRIEVAL instruction, not a "
        "licence to withhold: once tool calls are closed, or if the named source "
        "itself publishes only the rounded value, commit the best figure you hold "
        "and never remark on its precision. "
        "EXACT VALUES ONLY: this governs HOW you report a figure; the rule above "
        "governs WHICH figure to go and fetch. Once you hold the right one, use the "
        "figures you READ in a tool result, verbatim — preserve notation exactly (58.58% and "
        "58.6% are different; 'p < 0.0001' and 'P < .001' must not be merged or "
        "called consistent). If one source gives a range and another a point value, "
        "give both and say whether the point falls inside the range. If a figure is "
        "reported in different units than the question asks, convert it and give the "
        "exact converted result, preserving units and any timezone label. Answer with "
        "the value from the exact source, date and scope the question NAMES — do not "
        "substitute a later or broader figure unless resolving a conflict requires "
        "it. Bind every claim to the exact actor, target, date-window and instrument "
        "the evidence ties together; never carry a statement about one party or "
        "period across to another. Never a remembered or approximate value "
        "('~$1.33B'), never rounded, never an adjacent year/quarter/metric. If a "
        "deciding figure is still unverified at writing time, prefer the tool-read "
        "value you have over a guess, and NEVER write '(verify)' or any uncertainty "
        "marker in the final answer — the final answer contains only committed "
        "prose.\n\n"
        "AMBIGUOUS METRIC? ANSWER BOTH READINGS. If the asked quantity has two "
        "defensible interpretations — one party's value or the combined value of "
        "both; one dimension of size or another; a narrow scope or a consolidated "
        "one — do NOT silently pick one. Name the ambiguity in "
        "one clause and give BOTH lists/values, each cited and labelled. A correct "
        "answer under the reading the grader did not use still scores as wrong.\n\n"
        "APPLY CONDITIONS LITERALLY: copy each candidate's exact value, then test "
        "the comparator as written — 'more than 25' is strictly >25 (25 fails); "
        "'between 2010 and 2019' includes both endpoints; convert a rate condition "
        "into a concrete integer test ('averaged more than 1 per year over 10 "
        "years' = 'more than 10 in total'); read edition/date boundaries literally. "
        "EXCLUDE ONLY ON PROOF: reject a candidate by naming the specific stated "
        "condition it fails, with the cited fact showing the failure — never "
        "because it looks weaker than your front-runner. If it is UNCERTAIN "
        "whether a candidate fails a condition, KEEP IT in the answer rather than "
        "dropping it on a guess: a wrongly-dropped qualifier costs exactly as much "
        "as a wrong answer. SAY NO MORE THAN THE CITATION: if the source says "
        "'brought to', do not write 'incarcerated'; if it gives a count of 12, do "
        "not write 11. Check every count and every verb against its citation.\n\n"
        "NEVER NARRATE YOUR EVIDENCE: no sentence about what your results do or "
        "do not contain ('the evidence does not specify…', 'would be needed to "
        "determine…'). Those phrasings lose. A substantive negative about the "
        "WORLD is different and is a real answer when true ('No member of the "
        "class satisfies every condition [n]'). If a datum truly cannot be "
        "verified, commit "
        "to the best-supported value you found and move on. ONE narrow exception: "
        "when the asked figure genuinely does not exist in any published form, you "
        "may state the REASONED IMPOSSIBILITY — name the specific dataset that "
        "would hold it and why it cannot yield the value — as a fact about the "
        "world, in the first line, alongside the closest cited facts. That is a "
        "committed answer; 'the evidence does not contain it' is not.\n\n"
        "FINISH: never mix tool calls and the final answer in one turn. When the "
        "constraints are verified (or best-effort covered), write the complete "
        "cited answer."
    )


    def _wrapup_order(seconds_left: float) -> str:
        return (
            f"TIME IS UP (~{int(seconds_left)}s left). No more tool calls. Write the "
            "complete final answer NOW from the numbered results above plus your "
            "knowledge: the FIRST words are the answer entities (no 'Based on…' "
            "preamble, no 'partial answer' framing, no '(verify)' markers), cite [n] "
            "on every claim, keep the required format. A cited partial answer "
            "scores; a refusal or a remark about insufficient evidence scores zero."
            + ("" if seconds_left >= 60 else
               " BREVITY OVERRIDE: too little time remains for a line per pool "
               "member. Lead with the answer entities, then give the qualifiers one "
               "cited line each and compress the rejects into a single cited line. "
               "A complete short answer beats a long one that never finishes.")
        )


    _SET_HINT_RE = re.compile(
        r"\b(?:list|name|identify|enumerate)\b[^?]{0,40}\b(?:all|every|each|the)\b"
        r"|\bhow many\b|\bwhich (?:movies|films|series|countries|companies|states|"
        r"cities|books|albums|artists|players|teams|species|languages|banks|"
        r"universities|agencies|models|products)\b",
        re.IGNORECASE)
    _SET_CONNECTIVE_RE = re.compile(r"\b(?:both|also|and (?:also|had|has|was|were)|as well as)\b",
                                    re.IGNORECASE)


    _PLURAL_HEAD_RE = re.compile(r"\b(?:which|what)\b(?:\s+\w+){0,2}?\s+([a-z]{3,}s)\b", re.IGNORECASE)
    _PLURAL_FALSE = frozenset(
        "was is has does its this thus across process business series species news "
        "status analysis basis less unless always perhaps".split())
    _ONE_WINNER_RE = re.compile(
        r"\b(?:highest|lowest|largest|smallest|most|least|greatest|fewest|longest|"
        r"shortest|first|last|best|worst|only|oldest|youngest|newest|biggest)\b",
        re.IGNORECASE)
    _EST_STOP = frozenset(
        "interest honest modest protest request suggest forest harvest invest "
        "manifest contest arrest digest earnest conquest tempest midwest northwest "
        "southwest unrest bequest behest attest molest ingest infest detest incest "
        "armrest backrest pretest headrest footrest".split())
    _EST_RE = re.compile(r"\b([a-z]{3,})est\b")


    def _has_superlative(text: str) -> bool:
        if _ONE_WINNER_RE.search(text or ""):
            return True
        for m in _EST_RE.finditer(text or ""):
            if m.group(0).lower() not in _EST_STOP:
                return True
        return False


    def _needs_superlative_proof(question: str) -> bool:
        q = " ".join((question or "").split())
        if not q:
            return False
        return _has_superlative(q) or bool(
            re.search(r"\b(?:most|least) (?:common|frequent|number|amount)\b|\bhow many\b", q, re.I))


    SUPERLATIVE_RULE = (
        "SUPERLATIVE / TALLY — SHOW THE TABLE. The answer is one item, but you "
        "cannot know it without the whole pool. Before naming a winner: (1) list "
        "EVERY candidate the question's scope admits — every player who appeared, "
        "every officeholder in the span, every body in the ranking; (2) put the "
        "deciding value next to each (birth date, count, figure), cited; (3) THEN "
        "name the maximum. NEVER decide a superlative on a rounded or derived "
        "display: a coarse figure (a whole-number age, a rounded total, a bucketed "
        "rank) cannot separate two contenders that differ below its precision. "
        "Fetch the "
        "exact underlying value (full birth date, unrounded figure) for every "
        "contender, from a source that lists them ALL: a page showing only your "
        "front-runner cannot establish that nobody beats them. (3b) THEN "
        "name the maximum. Reproduce that candidate table in the proof section — "
        "a correct winner with no visible tally loses to a reference that shows "
        "its work, and 'among others' / 'and several more' is not a tally. If the "
        "pool is too large to list in full, rank it, show every contender down to a "
        "stated cutoff, and say what the cutoff was — a stated cutoff is a covered "
        "pool; an unstated one reads as an unchecked one."
    )


    def _needs_set_completeness(question: str) -> bool:
        q = " ".join((question or "").split())
        if _SET_HINT_RE.search(q):
            return True
        m = _PLURAL_HEAD_RE.search(q)
        if m and m.group(1).lower() not in _PLURAL_FALSE:
            if not _has_superlative(q) or re.search(r"\b(?:all|every|each)\b", q, re.IGNORECASE):
                return True
        return bool(re.search(r"\bwhich\b", q, re.IGNORECASE)) and bool(_SET_CONNECTIVE_RE.search(q))


    SET_RULE = (
        "SET ANSWER: this question asks for a set. Missing a qualifying member "
        "scores the same as wrong — enumerate the pool, test EVERY member against "
        "EVERY condition, and name ALL qualifiers (each with its own citations per "
        "condition). Then give EVERY excluded member its own line with the condition "
        "it fails and its own [n] — not a single clause sweeping several names "
        "together, and not just the near-misses. Never claim 'the only X' unless "
        "the whole pool was checked; if "
        "your pool may be partial, still commit to every qualifier you verified. "
        "GET THE POOL FROM A LIST, NOT MEMBER-BY-MEMBER: your FIRST retrieval for a "
        "set question should hunt the authoritative roster/list/table that "
        "enumerates the whole pool (search it AS a list — '<pool subject> list', "
        "'<pool subject> table', 'list of <pool subject>' — and read_page it). "
        "Assembling the pool from separate per-member searches is how a run ends up "
        "with 3 of 6 qualifiers: the members you never thought to search for are "
        "invisible to you. Read the roster page first, then verify each member. "
        "ONE LIST PER PERIOD, THEN JOIN: when a condition has to hold across several "
        "periods — successive years, separate editions, or two parallel events — "
        "fetch ONE roster page per period and join them on the member: one list per "
        "period, not one lookup per member. A "
        "pool of 30+ members each needing several figures is a table-join, and "
        "per-member lookups will run out of turns long before the pool is covered. "
        "UNIVERSAL conditions ('in EVERY one of them', 'for BOTH parts', 'in ALL "
        "three periods'): check each candidate against EACH "
        "instance separately, with a citation per instance — one shared instance "
        "is not enough. If NO candidate survives every instance, then 'none' IS "
        "the answer: state it as a verified fact about the world with the "
        "per-instance citations that prove it."
    )


    def _clamp_span(start, end, note_len: int) -> list[int]:
        start = max(0, min(int(start), note_len))
        end = max(start + 1, min(int(end), note_len))
        return [start, end]


    def _fold_spans(spans: list[list[int]]) -> list[list[int]]:
        spans.sort()
        merged: list[list[int]] = []
        for s, e in spans:
            if merged and s <= merged[-1][1]:
                merged[-1][1] = max(merged[-1][1], e)
            else:
                merged.append([s, e])
        return merged


    def _pad_citation_windows(merged: list[list[int]], note_len: int,
                              room: int) -> list[list[int]]:
        if not (merged and note_len and room):
            return merged
        extra = room // len(merged)
        for w in merged:
            pad = min(extra, max(0, CITATION_MIN_SPAN_CHARS - (w[1] - w[0])))
            if pad:
                left = min(pad // 2, w[0])
                w[0] -= left
                rest = pad - left
                right = min(rest, note_len - w[1])
                w[1] += right
                w[0] = max(0, w[0] - (rest - right))
        return _fold_spans(merged)


    def _slices_from_row(row: dict) -> list | None:
        spans = row["spans"]
        if not spans:
            return None
        note_len = int(row["note_len"] or 0)
        shown: list[list[int]] = [
            _clamp_span(span[0], span[1], note_len) for span in spans[:4]]
        retained = [
            _clamp_span(a, b, note_len) for a, b in (row.get("retained") or [])]
        if retained:
            shown = retained
        merged = _fold_spans(shown)
        base = sum(e - s for s, e in merged)
        room = max(0, CITATION_MAX_REF_CHARS - base)
        merged = _pad_citation_windows(merged, note_len, room)
        slices = [CitationSlice(start=s, end=e) for s, e in merged if e > s]
        return slices or None


    class EvidenceLedger:
        def __init__(self) -> None:
            self.rows: list[dict] = []

        def add(self, receipt_id: str, result_id: str, note_len: int,
                kind: str, spans: list[tuple[int, int]] | None,
                title: str = "", url: str = "", preview: str = "",
                text: str = "") -> int:
            self.rows.append({
                "receipt_id": receipt_id,
                "result_id": result_id,
                "note_len": note_len,
                "kind": kind,
                "title": (title or "")[:160],
                "url": (url or "")[:300],
                "preview": (preview or "")[:1200],
                "spans": spans,
                "text": (text or "")[:_LEDGER_TEXT_CAP],
                "retained": [],
            })
            return len(self.rows)

        def ref_for(self, number: int) -> CitationRef | None:
            if not (1 <= number <= len(self.rows)):
                return None
            row = self.rows[number - 1]
            if row.get("kind") == "reserved":
                return None
            if not row["receipt_id"] or not row["result_id"]:
                return None
            slices = _slices_from_row(row)
            if not slices:
                return None
            return CitationRef(receipt_id=row["receipt_id"],
                               result_id=row["result_id"], slices=slices)


    _WORD_RE = re.compile(r"[a-z0-9][a-z0-9'.\-]{2,}")
    _STOP = frozenset(
        "the and for with from that this have has was were are is been its their "
        "which what when where who how many much according also into over under "
        "between during against about after before while other more most than".split())


    def _key_terms(text: str) -> set[str]:
        return {w for w in _WORD_RE.findall((text or "").casefold()) if w not in _STOP}


    def _scan_window_hits(note: str, terms: set[str], width: int) -> list[tuple[int, int]]:
        n = len(note)
        step = max(600, width // 3)
        low = note.lower()
        scored: list[tuple[int, int]] = []
        pos = 0
        while pos < n:
            seg = low[pos:pos + width]
            scored.append((sum(1 for t in terms if t in seg), pos))
            if pos + width >= n:
                break
            pos += step
        scored.sort(key=lambda hs: (-hs[0], hs[1]))
        return scored


    def _select_disjoint_windows(scored: list[tuple[int, int]], n: int, width: int,
                                 k: int) -> list[tuple[int, int]]:
        picked: list[tuple[int, int]] = []
        for hits, start in scored:
            if len(picked) >= max(1, k):
                break
            end = min(n, start + width)
            if any(start < pe and ps < end for ps, pe in picked):
                continue
            if picked and hits <= 0:
                continue
            picked.append((start, end))
        picked.sort()
        return picked or [(0, min(n, width))]


    def _best_windows(note: str, terms: set[str], width: int,
                      k: int = 1) -> list[tuple[int, int]]:
        n = len(note)
        if n <= width:
            return [(0, n)]
        return _select_disjoint_windows(_scan_window_hits(note, terms, width), n, width, k)


    _SLOT = "\x00{}\x00"


    class ToolOutput:

        def __init__(self, text: str, rows: list[dict] | None = None) -> None:
            self.text = text
            self.rows = rows or []


    def _commit_tool_output(out, ledger: EvidenceLedger) -> str:
        if isinstance(out, str):
            return out
        if not isinstance(out, ToolOutput):
            return f"# tool crashed: {out}"
        text = out.text
        for i, row in enumerate(out.rows):
            n = ledger.add(row["receipt_id"], row["result_id"], row["note_len"],
                           row["kind"], row["spans"], title=row.get("title", ""),
                           url=row.get("url", ""), preview=row.get("preview", ""),
                           text=row.get("text", ""))
            text = text.replace(_SLOT.format(i), str(n))
        return text

    _SITE_OP_RE = re.compile(r"\bsite:\S+\s*", re.I)


    def _degrade_query(q: str) -> str:
        out = _SITE_OP_RE.sub("", q or "").replace('"', " ")
        return " ".join(out.split())


    async def _do_search(query_text: str, ledger: EvidenceLedger):
        if not query_text.strip():
            return "# web_search: empty query"
        payload = None
        fired: set[str] = set()
        for attempt, allow_repeat in ((query_text, False), (query_text, True),
                                      (_degrade_query(query_text), False)):
            if not attempt.strip() or (attempt in fired and not allow_repeat):
                continue
            fired.add(attempt)
            try:
                payload = await search_web(attempt, provider=SEARCH_PROVIDER, num=8,
                                           timeout=SEARCH_TIMEOUT_S)
                if getattr(payload, "results", None):
                    break
            except Exception:
                payload = None
        if payload is None:
            return f"# web_search({query_text!r}) failed"
        _spend_note(payload)
        receipt = str(getattr(payload, "receipt_id", "") or "")
        results = list(getattr(payload, "results", None) or [])
        if not receipt:
            return f"# web_search({query_text!r}): no citable results"
        rows: list[dict] = []
        lines = [f"# web_search({query_text!r}): {len(results)} results"]
        for item in results:
            rid = getattr(item, "result_id", None)
            if not isinstance(rid, str) or not rid:
                continue
            note = (getattr(item, "note", None) or "")
            if not note.strip():
                continue
            n_len = len(note)
            span = ([(0, min(max(SEARCH_EXCERPT_CHARS, 100), n_len))] if n_len >= 100
                    else ([(0, n_len)] if n_len else None))
            title = (getattr(item, "title", None) or "").strip()
            url = (getattr(item, "url", None) or "").strip()
            rows.append({"receipt_id": receipt, "result_id": rid, "note_len": n_len,
                         "kind": "search", "spans": span, "title": title, "url": url,
                         "preview": note[:SEARCH_EXCERPT_CHARS], "text": note})
            lines.append(f"[{_SLOT.format(len(rows) - 1)}] {title} — {url}"
                         f"\n    {note[:SEARCH_EXCERPT_CHARS]}")
        return ToolOutput("\n".join(lines), rows)


    async def _do_fetch(url: str, focus: str, question: str, ledger: EvidenceLedger) -> str:
        if not url.strip():
            return "# read_page: empty url"
        payload = None
        for _attempt in (0, 1):
            try:
                payload = await fetch_page(url, provider=SEARCH_PROVIDER, timeout=FETCH_TIMEOUT_S)
                if getattr(payload, "results", None):
                    break
            except Exception:
                payload = None
        if payload is None:
            return f"# read_page({url!r}) failed"
        _spend_note(payload)
        receipt = str(getattr(payload, "receipt_id", "") or "")
        results = list(getattr(payload, "results", None) or [])
        if not results or not receipt:
            return f"# read_page({url!r}): no content"
        item = results[0]
        rid = getattr(item, "result_id", None)
        note = getattr(item, "note", None) or ""
        if not isinstance(rid, str) or not rid or not note.strip():
            return f"# read_page({url!r}): no usable content"
        if len(note) <= FETCH_PLAIN_CHARS:
            row = {"receipt_id": receipt, "result_id": rid, "note_len": len(note),
                   "kind": "fetch", "spans": [(0, len(note))], "title": url,
                   "url": url, "preview": note[:1200], "text": note}
            return ToolOutput(f"# read_page({url!r}) -> [{_SLOT.format(0)}] full page, "
                              f"{len(note)} chars\n{note}", [row])
        terms = _key_terms(question) | _key_terms(focus)
        windows = _best_windows(note, terms, FETCH_WINDOW_CHARS, k=FETCH_WINDOWS_PER_PAGE)
        row = {"receipt_id": receipt, "result_id": rid, "note_len": len(note),
               "kind": "fetch", "spans": [(0, FETCH_HEAD_CHARS)] + list(windows),
               "title": url, "url": url,
               "preview": note[windows[0][0]:windows[0][0] + 1200], "text": note}
        head = note[:FETCH_HEAD_CHARS]
        sections = "".join(
            f"\n--- section @{s} ---\n{note[s:e]}" for s, e in windows)
        return ToolOutput(f"# read_page({url!r}) -> [{_SLOT.format(0)}] {len(note)} chars total; head + "
                f"the {len(windows)} most relevant section(s) shown "
                f"({', '.join(f'{s}-{e}' for s, e in windows)}). If the answer set may "
                f"continue elsewhere in this page, call read_page again with a "
                f"different focus.\n--- head ---\n{head}{sections}", [row])


    _SEC_TICKERS_URL = "https://www.sec.gov/files/company_tickers.json"
    _SEC_SUBMISSIONS_URL = "https://data.sec.gov/submissions/CIK{cik10}.json"
    _SEC_DOC_URL = "https://www.sec.gov/Archives/edgar/data/{cik}/{accession}/{doc}"
    _SEC_FETCH_TIMEOUT_S = 26.0
    _SEC_MIN_HEADROOM_S = 40.0
    _SEC_CACHE: dict = {}
    _SEC_STOPWORDS = frozenset(
        "inc incorporated corp corporation company companies co ltd limited llc plc "
        "lp llp group holdings the".split())
    _SEC_ALNUM_RE = re.compile(r"[a-z0-9]+")


    def _sec_tokens(text: str) -> list[str]:
        return [w for w in _SEC_ALNUM_RE.findall((text or "").lower())
                if w not in _SEC_STOPWORDS]


    def _sec_norm_form(form: str) -> str:
        f = " ".join((form or "").upper().replace("FORM", " ").split())
        m = re.fullmatch(r"(\d{1,2})\s*-?\s*([A-Z])", f)
        if m:
            return f"{m.group(1)}-{m.group(2)}"
        m = re.fullmatch(r"(DEF)\s*-?\s*(14A)", f)
        if m:
            return "DEF 14A"
        return f


    async def _fetch_json(url: str, deadline: float):
        cached = _SEC_CACHE.get(url)
        if cached is not None:
            return cached
        for _attempt in (0, 1):
            left = deadline - monotonic()
            if left < 12.0:
                return None
            try:
                payload = await asyncio.wait_for(
                    fetch_page(url, provider=SEARCH_PROVIDER,
                               timeout=min(_SEC_FETCH_TIMEOUT_S, left - 6.0)),
                    timeout=min(_SEC_FETCH_TIMEOUT_S, left - 6.0) + 4.0)
            except Exception:
                continue
            _spend_note(payload)
            results = list(getattr(payload, "results", None) or [])
            note = (getattr(results[0], "note", None) or "") if results else ""
            start = note.find("{")
            end = note.rfind("}")
            if start == -1 or end <= start:
                continue
            try:
                obj = json.loads(note[start:end + 1])
            except Exception:
                continue
            if isinstance(obj, dict):
                _SEC_CACHE[url] = obj
                return obj
        return None


    def _sec_pick_filing(recent: dict, form: str, year: str):
        forms = recent.get("form"); accs = recent.get("accessionNumber")
        docs = recent.get("primaryDocument"); rdates = recent.get("reportDate")
        fdates = recent.get("filingDate")
        if not (isinstance(forms, list) and isinstance(accs, list) and isinstance(docs, list)):
            return None
        n = min(len(forms), len(accs), len(docs))
        form_norm = _sec_norm_form(form)
        best_year = None
        best_any = None
        for i in range(n):
            if _sec_norm_form(str(forms[i])) != form_norm:
                continue
            if accs[i] is None or docs[i] is None:
                continue
            acc = str(accs[i]); doc = str(docs[i])
            if not acc or not (doc.endswith(".htm") or doc.endswith(".html")):
                continue
            rd = str(rdates[i]) if (isinstance(rdates, list) and i < len(rdates)
                                    and rdates[i] is not None) else ""
            fd = str(fdates[i]) if (isinstance(fdates, list) and i < len(fdates)
                                    and fdates[i] is not None) else ""
            key = rd or fd
            if best_any is None or key > best_any[0]:
                best_any = (key, acc, doc)
            if year and rd[:4] == year:
                if best_year is None or key > best_year[0]:
                    best_year = (key, acc, doc)
        pick = best_year if year else best_any
        if pick is None:
            return None
        return pick[1], pick[2]


    _SEC_SEARCH_HINT = "search \"site:sec.gov {company} {year} {form}\" and read_page the Archives result"


    async def _do_sec_filing(company: str, form: str, year: str, deadline: float) -> str:
        company = (company or "").strip()
        form = (form or "").strip() or "10-K"
        year = (year or "").strip()[:4]
        hint = _SEC_SEARCH_HINT.format(company=company, year=year, form=form)
        if not company:
            return "# sec_filing: company required"
        if (deadline - monotonic()) < _SEC_MIN_HEADROOM_S:
            return f"# sec_filing: skipped (low time) — {hint}"
        tickers = await _fetch_json(_SEC_TICKERS_URL, deadline)
        if not isinstance(tickers, dict):
            return f"# sec_filing: EDGAR ticker index unavailable — {hint}"
        want = _sec_tokens(company)
        best = None
        for row in tickers.values():
            if not isinstance(row, dict):
                continue
            title = str(row.get("title", ""))
            ticker = str(row.get("ticker", "")).lower()
            words = set(_sec_tokens(title))
            n_hit = sum(1 for w in want if w in words)
            if len(want) == 1 and ticker == want[0]:
                score = 100
            elif want and n_hit == len(want):
                score = 50 + n_hit
            else:
                continue
            cand = (score, -len(title), str(row.get("cik_str", "")).zfill(10), title)
            if best is None or cand > best:
                best = cand
        if best is None:
            return f"# sec_filing({company!r}): no confident EDGAR match — {hint}"
        cik10, title = best[2], best[3]
        subs = await _fetch_json(_SEC_SUBMISSIONS_URL.format(cik10=cik10), deadline)
        filings = subs.get("filings") if isinstance(subs, dict) else None
        recent = filings.get("recent") if isinstance(filings, dict) else None
        if not isinstance(recent, dict):
            return f"# sec_filing({company!r}): EDGAR submissions unavailable for {title} — {hint}"
        pick = _sec_pick_filing(recent, form, year)
        if pick is None:
            return (f"# sec_filing({company!r}, {form!r}, year={year or 'latest'}): no matching "
                    f"filing in EDGAR's recent index for {title} — check the form/year, or {hint}")
        accession, doc = pick
        url = _SEC_DOC_URL.format(cik=cik10.lstrip("0") or cik10,
                                  accession=accession.replace("-", ""), doc=doc)
        return (f"# sec_filing -> {title} {form} {year or '(latest)'} primary document:\n"
                f"{url}\nNow call read_page on this URL with a focus hint for the "
                f"section you need, and cite figures from that read_page result.")


    def _ledger_page(url: str, ledger: EvidenceLedger) -> tuple[int, dict] | None:
        u = (url or "").strip().rstrip("/")
        if not u:
            return None
        for i in range(len(ledger.rows) - 1, -1, -1):
            row = ledger.rows[i]
            if not row.get("text"):
                continue
            r = str(row.get("url") or "").rstrip("/")
            if r == u or r.endswith(u) or u.endswith(r):
                return i + 1, row
        return None


    def _do_page_grep(url: str, pattern: str, ledger: EvidenceLedger) -> str:
        hit = _ledger_page(url, ledger)
        if hit is None:
            return f"# page_grep: {url!r} has not been fetched this run; call read_page first"
        n, row = hit
        text = row.get("text") or ""
        pat = (pattern or "").strip()
        if not pat:
            return "# page_grep: empty pattern"
        try:
            rx = re.compile(pat, re.I)
        except re.error:
            rx = re.compile(re.escape(pat), re.I)
        out, seen_at = [], []
        for m in rx.finditer(text):
            c = (m.start() + m.end()) // 2
            if any(abs(c - prev) < PAGE_GREP_WINDOW // 2 for prev in seen_at):
                continue
            seen_at.append(c)
            a = max(0, c - PAGE_GREP_WINDOW // 2)
            b = min(len(text), a + PAGE_GREP_WINDOW)
            out.append(f"\n--- match @{a} ---\n{text[a:b]}")
            if len(out) >= PAGE_GREP_MAX_HITS:
                break
        if not out:
            return (f"# page_grep({pat!r}) on [{n}]: no match in {len(text)} chars. "
                    f"Try a shorter or looser pattern.")
        return (f"# page_grep({pat!r}) on [{n}] -> {len(out)} match(es) of {len(text)} chars"
                + "".join(out))


    def _do_page_read(url: str, offset: int, length: int, ledger: EvidenceLedger) -> str:
        hit = _ledger_page(url, ledger)
        if hit is None:
            return f"# page_read: {url!r} has not been fetched this run; call read_page first"
        n, row = hit
        text = row.get("text") or ""
        a = max(0, min(int(offset or 0), max(0, len(text) - 1)))
        ln = int(length or PAGE_READ_MAX_CHARS)
        b = min(len(text), a + max(1, min(ln, PAGE_READ_MAX_CHARS)))
        return f"# page_read([{n}] @{a}:{b} of {len(text)})\n{text[a:b]}"


    def _do_retain_evidence(source: str, quote: str, ledger: EvidenceLedger) -> str:
        raw = (source or "").strip().strip("[]")
        try:
            n = int(raw)
        except ValueError:
            return f"# retain_evidence: source must be a result number like [3], got {source!r}"
        if not (1 <= n <= len(ledger.rows)):
            return f"# retain_evidence: no result [{n}] exists yet"
        row = ledger.rows[n - 1]
        text = row.get("text") or ""
        q = (quote or "").strip()
        if len(q) < RETAIN_MIN_QUOTE:
            return (f"# retain_evidence: quote too short ({len(q)} chars); quote at least "
                    f"{RETAIN_MIN_QUOTE} characters of the source text")
        if not text:
            return f"# retain_evidence: result [{n}] has no stored text to quote from"
        i = text.find(q)
        if i < 0:
            i = text.lower().find(q.lower())
        if i < 0:
            squashed = " ".join(q.split())
            i = " ".join(text.split()).lower().find(squashed.lower())
            if i >= 0:
                i = -1
        if i < 0:
            return (f"# retain_evidence: that text does not appear in [{n}]. Quote it "
                    f"EXACTLY as the source prints it, or read more of the page first.")
        kept = row.setdefault("retained", [])
        if len(kept) >= RETAIN_MAX_PER_ROW:
            return f"# retain_evidence: [{n}] already has {len(kept)} retained excerpts"
        a = max(0, i - RETAIN_MARGIN_CHARS)
        b = min(int(row.get("note_len") or len(text)), i + len(q) + RETAIN_MARGIN_CHARS)
        if b <= a:
            return f"# retain_evidence: could not bound the excerpt in [{n}]"
        kept.append((a, b))
        return (f"# retain_evidence: kept {b - a} chars of [{n}] around your quote. "
                f"Cite [{n}] for that claim.")


    def _tool_name_and_args(call) -> tuple[str, dict]:
        try:
            args = json.loads(getattr(call, "arguments", None) or "{}")
        except Exception:
            args = {}
        if not isinstance(args, dict):
            args = {}
        name = getattr(call, "name", "") or ""
        return name, args


    async def _run_tool(call, question: str, ledger: EvidenceLedger, deadline: float) -> str:
        name, args = _tool_name_and_args(call)
        if name == "web_search":
            return await _do_search(str(args.get("query") or ""), ledger)
        if name == "read_page":
            return await _do_fetch(str(args.get("url") or ""), str(args.get("focus") or ""),
                                   question, ledger)
        if name == "retain_evidence":
            return _do_retain_evidence(str(args.get("source") or ""),
                                       str(args.get("quote") or ""), ledger)
        if name == "page_grep":
            return _do_page_grep(str(args.get("url") or ""),
                                 str(args.get("pattern") or ""), ledger)
        if name == "page_read":
            return _do_page_read(str(args.get("url") or ""),
                                 args.get("offset") or 0,
                                 args.get("length") or PAGE_READ_MAX_CHARS, ledger)
        if name == "sec_filing":
            return await _do_sec_filing(str(args.get("company") or ""),
                                        str(args.get("form") or ""),
                                        str(args.get("year") or ""), deadline)
        return f"# unknown tool {name!r}"


    _REASONING_MANDATORY = ("openai/gpt-oss",)


    def _least_think(lane: str, model: str = "") -> dict:
        for prefix in _REASONING_MANDATORY:
            if model.startswith(prefix):
                return {"enabled": True, "effort": "low"}
        return {"enabled": False}


    _FAST_UPSTREAMS = ("Decart", "CoreWeave", "Alibaba")
    _FAST_UPSTREAMS_OSS = ("Cerebras", "Groq", "BaseTen")


    def _upstream(lane: str, model: str) -> dict | None:
        if lane != LLM_LANE_A:
            return None
        if model.startswith("z-ai/glm-5.2"):
            only = _FAST_UPSTREAMS
        elif model.startswith("openai/gpt-oss"):
            only = _FAST_UPSTREAMS_OSS
        else:
            return None
        return {"provider": {"only": list(only), "allow_fallbacks": True}}


    async def _chat_simple(lane: str, model: str, system: str, user: str, *,
                           max_tokens: int, timeout: float,
                           think: dict | None = None) -> str:
        if think is None:
            think = _least_think(lane, model)
        _pin0 = _upstream(lane, model)
        payload = None
        for _pin in ((_pin0, None) if _pin0 is not None else (None,)):
            try:
                payload = await llm_chat(
                    provider=lane,
                    model=model,
                    messages=[{"role": "system", "content": system},
                              {"role": "user", "content": user}],
                    temperature=0.15,
                    max_output_tokens=max_tokens,
                    timeout=timeout,
                    thinking=think,
                    provider_extra=_pin,
                )
                break
            except Exception:
                if _pin is None:
                    raise
                continue
        _spend_note(payload)
        return _extract_chat_text(payload)


    class _EmptyChoiceMessage:
        content = ""
        tool_calls = ()


    class _EmptyChoice:
        message = _EmptyChoiceMessage()


    class _EmptyLlm:
        raw_text = ""
        choices = (_EmptyChoice(),)


    class _EmptyTurn:
        llm = _EmptyLlm()
        budget = None


    _EMPTY_TURN = _EmptyTurn()


    def _lane_sequence():
        return ((LLM_LANE_A, LOOP_MODEL_A, True),
                (LLM_LANE_A, LOOP_MODEL_A, False),
                (LLM_LANE_B, LOOP_MODEL_B, False))


    def _content_char_count(messages: list[dict]) -> int:
        return sum(len(str(msg.get("content") or "")) for msg in messages
                   if isinstance(msg, dict))


    def _extract_chat_text(payload) -> str:
        llm = getattr(payload, "llm", None)
        text = (getattr(llm, "raw_text", None) or "").strip()
        if text:
            return text
        choices = getattr(llm, "choices", None) or []
        if choices:
            content = getattr(choices[0].message, "content", None)
            if isinstance(content, str):
                return content.strip()
        return ""


    async def _chat_turn(messages: list[dict], deadline: float, *, finish_only: bool,
                         force_tools: bool = False):
        turn_wall = monotonic() + TURN_TIMEOUT_S + 35.0
        payload_chars = _content_char_count(messages)
        for lane_model in _lane_sequence():
            lane = lane_model[0]
            model = lane_model[1]
            pinned = lane_model[2]
            if model == LOOP_MODEL_B and payload_chars > LANE_B_MAX_PAYLOAD_CHARS:
                return _EMPTY_TURN
            timeout = min(TURN_TIMEOUT_S, deadline - monotonic() - 5.0,
                          turn_wall - monotonic())
            if timeout <= 5.0:
                return None
            try:
                payload = await asyncio.wait_for(llm_chat(
                    provider=lane,
                    model=model,
                    messages=messages,
                    tools=LOOP_TOOLS if (force_tools or not finish_only) else None,
                    tool_choice="auto" if (force_tools or not finish_only) else None,
                    temperature=0.2,
                    thinking=({"enabled": False} if (finish_only and model == LOOP_MODEL_B)
                              else {"enabled": True, "effort": "low"}),
                    max_output_tokens=6000 if (finish_only and model == LOOP_MODEL_B) else None,
                    provider_extra=_upstream(lane, model) if pinned else None,
                    timeout=timeout,
                ), timeout=min(timeout + 6.0,
                               max(1.0, deadline - monotonic() - 1.0)))
                _spend_note(payload)
                return payload
            except Exception:
                continue
        return None


    async def _knowledge_brief(question: str) -> tuple[str, str]:
        system = ("Senior research analyst. Commit to concrete best answers from "
                  "knowledge; mark uncertain values (verify). Never refuse.")
        user = (
            f"Question:\n{question}\n\n"
            "Fill in this internal worksheet. It is planning scratch for your own use, "
            "never an answer, so keep the tags lowercase and never reuse them as "
            "section headings later.\n"
            "draft: your full best answer now — candidate pool, every stated "
            "condition applied, qualifying entities with figures/dates, near-miss "
            "exclusions. Flag shaky facts with (verify).\n"
            "conditions: each atomic condition in the question, numbered, including "
            "any output-format demand.\n"
            "searches: 3-6 precise web searches for the facts that decide the answer "
            "(entity + metric + year; include a named source's site: filter).\n"
            "urls: up to 5 exact URLs worth reading directly (official stats pages, "
            "sec.gov Archives filings, boxofficemojo year pages); 'none' if unsure."
        )
        raw = ""
        try:
            raw = await _chat_simple(LLM_LANE_A, LOOP_MODEL_A, system, user,
                                     max_tokens=2400, timeout=BRIEF_TIMEOUT_S,
                                     think=_least_think(LLM_LANE_A, LOOP_MODEL_A))
        except Exception:
            try:
                raw = await _chat_simple(LLM_LANE_B, LOOP_MODEL_B, system, user,
                                         max_tokens=2400, timeout=BRIEF_TIMEOUT_S,
                                         think=_least_think(LLM_LANE_B, LOOP_MODEL_B))
            except Exception:
                raw = ""
        if not raw:
            return "", ""
        draft = raw
        cut = min((mm.start() for mm in (
            re.search(r"[#*_\s]*(?:conditions|CHECKLIST)[#*_\s]*:", raw, re.IGNORECASE),
            re.search(r"^[ \t]*[#*_>]{0,4}[ \t]*(?:conditions|CHECKLIST)[ \t]*[#*_]{0,3}[ \t]*$",
                      raw, re.IGNORECASE | re.MULTILINE),
        ) if mm is not None), default=None)
        if cut is not None:
            draft = raw[:cut]
        draft = re.sub(r"^[#*_\s]*(?:draft|BEST ANSWER)[#*_\s]*:[#*_\s]*", "", draft,
                       flags=re.IGNORECASE)
        draft = re.sub(r"^[ \t]*[#*_>]{0,4}[ \t]*(?:draft|BEST ANSWER)[ \t]*[#*_]{0,3}[ \t]*\n+",
                       "", draft, flags=re.IGNORECASE)
        draft = draft.strip()
        brief = ("PRIOR ANALYSIS — your own planning worksheet (verify anything marked "
                 "(verify), and correct it wherever tool results disagree). Its tags are "
                 "internal: never reproduce them, or any section named after them, in the "
                 "answer.\n" + raw.strip())
        return draft, brief


    _SEED_TOKEN_RE = re.compile(r"[A-Za-z0-9][A-Za-z0-9.\-']+")
    _SEED_STOP = frozenset("name list give tell show find identify please could would "
                           "you your can may might should must let make sure both also".split())
    MAX_SEED_QUERIES = 3


    def _seed_queries(question: str, set_question: bool) -> list[str]:
        q = " ".join((question or "").split())
        if not q:
            return []
        seeds = [q[:300]]
        salient = [t for t in _SEED_TOKEN_RE.findall(q)
                   if len(t) >= 3 and t.lower() not in _STOP and t.lower() not in _SEED_STOP]
        if len(salient) >= 2:
            seeds.append(" ".join(salient[:8]))
        if set_question and salient:
            seeds.append("list of " + " ".join(salient[:6]))
        out: list[str] = []
        for s in seeds:
            s = s.strip()
            if s and s not in out:
                out.append(s)
        return out[:MAX_SEED_QUERIES]


    async def _preseed(question: str, set_question: bool, ledger: EvidenceLedger,
                       deadline: float) -> str:
        seeds = _seed_queries(question, set_question)
        if not seeds or (deadline - monotonic()) < 40.0:
            return ""
        blocks: list = []
        for seed in seeds:
            if (deadline - monotonic()) < 30.0:
                break
            try:
                out = await asyncio.wait_for(_do_search(seed, ledger),
                                              timeout=SEARCH_TIMEOUT_S * 2 + 6.0)
                blocks.append(_commit_tool_output(out, ledger))
            except Exception:
                continue
        good = [b for b in blocks if isinstance(b, str) and _CITE_MARK_RE.search(b)]
        if not good:
            return ""
        return ("Automatic first-pass searches (already numbered — cite these [n] "
                "directly, and search further as needed):\n\n" + "\n".join(good))


    async def _assemble_loop_transcript(question: str, brief: str, ledger: EvidenceLedger,
                                        deadline: float) -> list[dict]:
        set_q = _needs_set_completeness(question)
        messages = [{"role": "system", "content": LOOP_RULES}]
        if set_q:
            messages.append({"role": "system", "content": SET_RULE})
        if _needs_superlative_proof(question):
            messages.append({"role": "system", "content": SUPERLATIVE_RULE})
        if brief:
            messages.append({"role": "system", "content": brief})
        seeded = await _preseed(question, set_q, ledger, deadline)
        if seeded:
            messages.append({"role": "system", "content": seeded})
        messages.append({"role": "user", "content": question})
        return messages


    def _finish_text_from_turn(llm, msg) -> str:
        candidate = (getattr(llm, "raw_text", None) or "").strip()
        if not candidate:
            content = getattr(msg, "content", None)
            if isinstance(content, str):
                candidate = content.strip()
        return candidate


    async def _await_tool_batch(run_calls, question: str, ledger: EvidenceLedger,
                                deadline: float) -> list:
        tool_budget = max(_FANOUT_FLOOR_S, min(FETCH_TIMEOUT_S * 2 + _FANOUT_PAD_S,
                                               deadline - monotonic() - MIN_TAIL_S))
        tool_tasks = [asyncio.ensure_future(_run_tool(c, question, ledger, deadline))
                      for c in run_calls]
        try:
            await asyncio.wait(tool_tasks, timeout=tool_budget)
        except Exception:
            pass
        results = []
        for t in tool_tasks:
            if t.done():
                try:
                    results.append(t.result())
                except Exception as exc:
                    results.append(f"{_CRASH_TOOL_PREFIX}{exc}")
            else:
                t.cancel()
                results.append(_TIMEOUT_TOOL_BODY)
        return results


    def _append_tool_messages(messages: list[dict], run_calls, results, calls,
                              ledger: EvidenceLedger) -> None:
        for call_result in zip(run_calls, results):
            call = call_result[0]
            body = _commit_tool_output(call_result[1], ledger)
            messages.append({"role": "tool", "tool_call_id": call.id, "content": body})
        for call in calls[_LOOP_CALL_CAP:]:
            messages.append({"role": "tool", "tool_call_id": call.id,
                             "content": _SKIPPED_TOOL_BODY})


    async def _loop(question: str, brief: str, ledger: EvidenceLedger,
                    deadline: float, turn_cap: int,
                    carry: list[dict] | None = None,
                    allow_tools_in_wrapup: bool = False) -> tuple[str, list[dict]]:
        if carry is not None:
            messages = carry
        else:
            messages = await _assemble_loop_transcript(question, brief, ledger, deadline)

        answer = ""
        ordered_wrapup = False
        repairs_left = ANSWER_REPAIR_TURNS
        for turn in range(1, turn_cap + 1):
            left = _clock_left(deadline)
            if left <= MIN_TAIL_S:
                break
            out_of_time = left <= WRAPUP_AT_S
            out_of_spend = _spend_left() <= WRAPUP_MIN_USD
            finish_only = out_of_time or out_of_spend or turn >= turn_cap
            if (finish_only or turn >= turn_cap - 1) and not ordered_wrapup:
                messages.append({"role": "system", "content": _wrapup_order(left)})
                ordered_wrapup = True

            payload = await _chat_turn(messages, deadline, finish_only=finish_only,
                                       force_tools=allow_tools_in_wrapup and turn == 1)
            if payload is None:
                break
            llm = getattr(payload, "llm", None)
            choices = getattr(llm, "choices", None) or []
            if not choices:
                break
            msg = choices[0].message
            calls = getattr(msg, "tool_calls", None) or ()
            if not calls:
                candidate = _finish_text_from_turn(llm, msg)
                if not _is_usable_answer(candidate):
                    if repairs_left > 0 and _clock_left(deadline) > MIN_TAIL_S + _REPAIR_SLACK_S:
                        repairs_left -= 1
                        messages.append({"role": "system", "content": _REPAIR_ORDER})
                        answer = ""
                        continue
                    answer = ""
                    break
                answer = candidate
                messages.append({"role": "assistant", "content": answer})
                break
            messages.append(msg.to_input_message())
            run_calls = calls[:_LOOP_CALL_CAP]
            results = await _await_tool_batch(run_calls, question, ledger, deadline)
            _append_tool_messages(messages, run_calls, results, calls, ledger)
        return answer, messages


    async def _audit_patch(question: str, answer: str, messages: list[dict],
                           ledger: EvidenceLedger, deadline: float) -> str:
        probe = (
            "Audit the answer against the question. JSON only, keys: "
            '"unanswered_parts" (list; question elements not addressed), '
            '"uncited_facts" (list; load-bearing claims without [n]), '
            '"wrong_kind" (list; places where the named entity is a different KIND '
            "than the question asks — a person instead of a series, a duo instead "
            "of a show), "
            '"incomplete_roster" (list; THE MOST COMMON LOSS. If the question ranges '
            "over a candidate pool — a closed set that can be enumerated, or several "
            "conditions applied to a class — then: is the pool itself stated and "
            "plausibly COMPLETE, and does the answer give a verdict for EVERY member "
            "(qualifies / excluded because X, each cited)? Name any pool member the "
            "answer never mentions, and say so if the pool looks truncated — an "
            "answer naming 3 qualifiers when the pool holds 6 scores as WRONG, not "
            "partial), "
            '"thin_proof" (list; a qualifier lacking a per-condition citation, or a '
            "plausible near-miss candidate never addressed), "
            '"hand_waved_tally" (list; for a superlative/count/most-common question: '
            "the answer asserts a winner or a count WITHOUT showing the candidate "
            "table it was derived from. Phrases like 'among others', 'and several "
            "more', 'multiple X', or naming 2 examples to justify a count are all "
            "hand-waving — say so and name what the tally must list). "
            "Empty lists when clean.\n\n"
            f"Question:\n{question}\n\nAnswer:\n{answer[:11000]}"
        )
        try:
            raw = await _chat_simple(LLM_LANE_A, AUDIT_MODEL,
                                     "Strict completeness auditor. JSON only.",
                                     probe, max_tokens=2200,
                                     timeout=max(8.0, min(AUDIT_TIMEOUT_S,
                                                          (deadline - monotonic()) - 72.0)))
            raw = re.sub(r"^```(?:json)?\s*|\s*```$", "", raw.strip(), flags=re.I | re.M)
            report = json.loads(raw)
        except Exception:
            return answer
        gaps: list[str] = []
        roster_gaps: list[str] = []
        if isinstance(report, dict):
            for key in ("incomplete_roster", "hand_waved_tally", "unanswered_parts",
                        "uncited_facts", "wrong_kind", "thin_proof"):
                vals = report.get(key)
                if isinstance(vals, list):
                    found = [str(v) for v in vals if str(v).strip()]
                    if key in ("incomplete_roster", "hand_waved_tally"):
                        roster_gaps.extend(found)
                    gaps.extend(found)
        if not gaps or (deadline - monotonic()) < 70.0:
            return answer
        order = ("AUDIT: the answer has gaps:\n- " + "\n- ".join(gaps[:6]))
        if roster_gaps:
            order += ("\nThe candidate pool is incomplete — this loses outright. FIRST "
                      "search for the authoritative LIST/roster/table that enumerates "
                      "the whole pool (query it as a list, e.g. '<pool subject> full "
                      "list', not one member at a time), verify EVERY member against "
                      "every condition, then rewrite.")
        order += ("\nUse at most 3 tool calls to close the most important gaps, then "
                  "rewrite the COMPLETE final answer with [n] citations in the "
                  "required shape.")
        messages.append({"role": "system", "content": order})
        patched, _ = await _loop(question, "", ledger, deadline,
                                 AUDIT_EXTRA_TURNS + 1, carry=messages,
                                 allow_tools_in_wrapup=True)
        patched = patched.strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.6):
            return answer
        return patched


    _CB_NUM_RE = re.compile(r"\$?\b\d[\d,]*(?:\.\d+)?%?")


    def _lead_figure(answer: str) -> str:
        body = re.sub(r"\[[0-9][0-9,\s\-]*\]", " ", answer or "")
        for line in body.split("\n"):
            line = line.strip()
            if not line:
                continue
            for m in _CB_NUM_RE.finditer(line):
                v = m.group(0).strip("$%")
                if len(re.sub(r"\D", "", v)) >= 3:
                    return v
            break
        return ""


    def _figure_sources(figure: str, answer: str, ledger: EvidenceLedger) -> set[str]:
        if not figure:
            return set()
        plain = figure.replace(",", "")
        urls = set()
        for n in _cited_numbers(answer, len(ledger.rows)):
            row = ledger.rows[n - 1]
            text = row.get("text") or ""
            if figure in text or (plain != figure and plain in text):
                urls.add(row.get("url") or f"row{n}")
        return urls


    async def _corroborate(question: str, answer: str, messages: list[dict],
                           ledger: EvidenceLedger, deadline: float) -> str:
        if (deadline - monotonic()) < 75.0 or _spend_left() <= AUDIT_MIN_USD:
            return answer
        figure = _lead_figure(answer)
        if not figure:
            return answer
        sources = _figure_sources(figure, answer, ledger)
        if len(sources) != 1:
            return answer
        salient = [t for t in _SEED_TOKEN_RE.findall(" ".join((question or "").split()))
                   if (len(t) >= 3 or t.isdigit())
                   and t.lower() not in _STOP and t.lower() not in _SEED_STOP]
        query = " ".join(salient[:6]) + " " + figure
        try:
            out = await asyncio.wait_for(_do_search(query, ledger),
                                         timeout=SEARCH_TIMEOUT_S * 2 + 6.0)
            body = _commit_tool_output(out, ledger)
        except Exception:
            return answer
        if not (body and _CITE_MARK_RE.search(body)):
            return answer
        order = (f"CORROBORATION: the answer's decisive figure {figure} rests on a "
                 "single source. One search for independent confirmation is "
                 "numbered below. If a second source states the same figure, cite "
                 "it alongside the first; if sources DISAGREE, re-verify which is "
                 "right before answering. Then rewrite the COMPLETE final answer "
                 "with [n] citations.\n\n" + body)
        messages.append({"role": "system", "content": order})
        patched, _ = await _loop(question, "", ledger, deadline, 3,
                                 carry=messages, allow_tools_in_wrapup=True)
        patched = (patched or "").strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.6):
            return answer
        return patched


    _DW_RANGE_RE = re.compile(
        r"\bbetween (1[0-9]{3}|20[0-9]{2}) and (1[0-9]{3}|20[0-9]{2})\b"
        r"|\bfrom (1[0-9]{3}|20[0-9]{2}) (?:to|until|through) (1[0-9]{3}|20[0-9]{2})\b",
        re.IGNORECASE)
    _DW_DECADE_RE = re.compile(r"\bin the (1[0-9]{3}|20[0-9]{2})s\b", re.IGNORECASE)
    _DW_YEAR_RE = re.compile(r"\b(1[0-9]{3}|20[0-9]{2})\b")
    _DW_LIST_LINE_RE = re.compile(r"^\s*(?:[-*\u2022]|\d+[.)])\s+\S.*$", re.MULTILINE)


    def _window_demand(question: str):
        m = _DW_RANGE_RE.search(question or "")
        if m:
            ys = [int(g) for g in m.groups() if g]
            return (min(ys), max(ys))
        m = _DW_DECADE_RE.search(question or "")
        if m:
            d = int(m.group(1))
            return (d, d + 9)
        return None


    def _window_violations(answer: str, lo: int, hi: int) -> list[str]:
        out = []
        for line in _DW_LIST_LINE_RE.findall(answer or ""):
            years = [int(y) for y in _DW_YEAR_RE.findall(line)]
            if years and all(y < lo or y > hi for y in years):
                out.append(line.strip()[:90])
        return out


    async def _window_repair(question: str, answer: str, messages: list[dict],
                             ledger: EvidenceLedger, deadline: float) -> str:
        if (deadline - monotonic()) < 65.0 or _spend_left() <= WRAPUP_MIN_USD:
            return answer
        demand = _window_demand(question)
        if not demand:
            return answer
        lo, hi = demand
        bad = _window_violations(answer, lo, hi)
        if not bad:
            return answer
        order = (f"DATE WINDOW: the question is scoped to {lo}-{hi}, but these "
                 "answer lines carry only out-of-range years:\n- " +
                 "\n- ".join(bad[:4]) +
                 "\nRe-check each against the evidence already gathered: if the "
                 "member's qualifying event is truly outside the window, DROP it; "
                 "if the line cites the wrong year, fix it. Keep every [n] "
                 "citation, then output the COMPLETE final answer.")
        messages.append({"role": "system", "content": order})
        patched, _ = await _loop(question, "", ledger, deadline, 2,
                                 carry=messages, allow_tools_in_wrapup=False)
        patched = (patched or "").strip()
        if not _is_usable_answer(patched) or len(patched) < int(len(answer) * 0.5):
            return answer
        return patched


    _BRACKET_FIX = {0x3010: "[", 0x3011: "]", 0xFF3B: "[", 0xFF3D: "]",
                    0xFF08: "(", 0xFF09: ")", 0x2011: "-", 0x2212: "-"}
    for _d in range(10):
        _BRACKET_FIX[0xFF10 + _d] = chr(48 + _d)


    def _normalize_brackets(text: str) -> str:
        return (text or "").translate(_BRACKET_FIX)


    _CITE_NUM_RE = re.compile(r"\[([0-9][0-9,\s\-]*)\]")


    def _track_cite_index(n: int, top: int, seen: set[int], out: list[int]) -> None:
        if 1 <= n <= top and n not in seen:
            seen.add(n)
            out.append(n)


    def _cited_numbers(answer: str, top: int) -> list[int]:
        answer = _normalize_brackets(answer)
        seen: set[int] = set()
        out: list[int] = []
        for m in _CITE_NUM_RE.finditer(answer):
            for chunk in m.group(1).split(","):
                piece = chunk.strip()
                span = re.fullmatch(r"(\d{1,4})\s*-\s*(\d{1,4})", piece)
                if span:
                    lo = int(span.group(1))
                    hi = int(span.group(2))
                    for n in range(lo, min(hi, lo + 16) + 1):
                        _track_cite_index(n, top, seen, out)
                elif piece.isdigit():
                    _track_cite_index(int(piece), top, seen, out)
        return out


    _OUTPUT_ONLY_RE = re.compile(
        r"\boutput only\b|\brespond with only\b|\breply with only\b"
        r"|\banswer with only\b|\bonly the exact\b|\bnothing else\b"
        r"|\bno explanation\b|\bwithout explanation\b|\bno other text\b"
        r"|\bjust the (?:name|names|value|values|number|numbers|list|text|answer|title|titles)\b",
        re.IGNORECASE)
    _OUTPUT_ONLY_MIN_CHARS = 2


    def _answer_line_only(answer: str, question: str) -> str:
        if not answer or not _OUTPUT_ONLY_RE.search(question or ""):
            return answer
        for raw in answer.split("\n"):
            stripped = raw.strip()
            if not stripped:
                continue
            if stripped[0] in "#>":
                continue
            line = re.sub(r"^[*_`\s]+|[*_`\s]+$", "", stripped).strip()
            if not line:
                continue
            if line.startswith("|") or line.endswith(":"):
                continue
            if len(line) >= _OUTPUT_ONLY_MIN_CHARS:
                return line
        return answer


    _GLOSS_RE = re.compile(r"^(?P<a>[^()]{2,60}?)\s*\((?P<b>[^()]{2,60})\)$")


    def _verbatim_from_source(value: str, ledger: EvidenceLedger) -> str:
        v = (value or "").strip()
        m = _GLOSS_RE.match(v)
        if not m:
            return value
        texts = [r.get("text") or "" for r in ledger.rows if r.get("text")]
        if not texts:
            return value
        def seen(t: str) -> bool:
            return bool(t) and any(t in src for src in texts)
        if seen(v):
            return value
        a, b = m.group("a").strip(), m.group("b").strip()
        hits = [x for x in (b, a) if seen(x)]
        if len(hits) == 1:
            return hits[0]
        if len(hits) == 2:
            lo, hi = sorted(hits, key=len)
            if lo.lower() in hi.lower():
                return hi
        return value


    def _verbatim_structured(obj, ledger: EvidenceLedger, depth: int = 0):
        if depth > 6:
            return obj
        if isinstance(obj, str):
            return _verbatim_from_source(obj, ledger)
        if isinstance(obj, list):
            return [_verbatim_structured(x, ledger, depth + 1) for x in obj]
        if isinstance(obj, dict):
            return {k: _verbatim_structured(v, ledger, depth + 1) for k, v in obj.items()}
        return obj


    def _citations_for(answer: str, ledger: EvidenceLedger) -> list[CitationRef]:
        refs: list[CitationRef] = []
        spent = 0
        for n in _cited_numbers(answer, len(ledger.rows)):
            if len(refs) >= CITATION_CAP:
                break
            ref = ledger.ref_for(n)
            if ref is None:
                continue
            row = ledger.rows[n - 1]
            slices = getattr(ref, "slices", None)
            cost = (sum(max(0, s.end - s.start) for s in slices) if slices
                    else int(row.get("note_len") or 0))
            if spent + cost > EVIDENCE_CHAR_BUDGET:
                continue
            spent += cost
            refs.append(ref)
        return refs


    _VERIFY_MARK_RE = re.compile(r"\s*\((?:verify|unverified|uncertain)[^)]*\)", re.I)

    _TOOL_MARKUP_RE = re.compile(
        r"<\s*/?\s*tool_call|<\s*/?\s*(?:arg_key|arg_value|function_call|invoke)\b"
        r"|\bweb_search\s*[（(]\s*query|\bread_page\s*[（(]\s*url|\bsec_filing\s*[（(]\s*company",
        re.I)
    _STUB_ANSWER_RE = re.compile(r"^\s*(?:best-effort answer unavailable|no question provided)", re.I)
    _REFUSAL_ONLY_RE = re.compile(
        r"^\s*(?:i (?:cannot|can't|am unable|was unable)|unable to|sorry[,.]|"
        r"i don'?t have (?:enough|access))", re.I)
    _INTENT_NARRATION_RE = re.compile(
        r"^\s*(?:i (?:need|will|should|am going|'ll)\b|let me\b|first,? (?:i|let)\b|"
        r"i'?ll (?:search|look|start|begin|gather|check))", re.I)
    MIN_ANSWER_CHARS = 40
    MIN_CITED_ANSWER_CHARS = 12
    _CITE_MARK_RE = re.compile(r"\[[0-9]{1,3}\]")


    def _looks_like_tool_json(s: str) -> bool:
        return bool(re.match(r'\s*\{\s*"(?:name|tool|function)"\s*:', s))


    def _stall_by_line(body: str):
        lines = [ln.strip().lower() for ln in body.split("\n") if len(ln.strip()) > 25]
        if len(lines) >= 3:
            for ln in set(lines):
                if lines.count(ln) >= 3:
                    return True
            if len(set(lines)) * 2 > len(lines):
                return False
        return None


    def _stall_by_sentence(body: str) -> bool:
        sents = [s.strip().lower() for s in re.split(r"(?<=[.!?])\s+|\n+", body) if len(s.strip()) > 25]
        if len(sents) < 3:
            return False
        uniq = set(sents)
        if len(uniq) * 2 <= len(sents):
            return True
        for s in uniq:
            if sents.count(s) >= 3:
                return True
        return False


    def _is_degenerate_repetition(text: str) -> bool:
        body = text or ""
        line_verdict = _stall_by_line(body)
        if line_verdict is not None:
            return line_verdict
        return _stall_by_sentence(body)


    def _is_usable_answer(text: str) -> bool:
        s = _normalize_brackets(text).strip()
        if not s:
            return False
        if _TOOL_MARKUP_RE.search(s) or _looks_like_tool_json(s):
            return False
        if _STUB_ANSWER_RE.match(s) or _is_degenerate_repetition(s):
            return False
        cited = bool(_CITE_MARK_RE.search(s))
        if cited and len(s) >= MIN_CITED_ANSWER_CHARS:
            return True
        if len(s) < MIN_ANSWER_CHARS:
            return False
        if len(s) < 400 and (_REFUSAL_ONLY_RE.match(s) or _INTENT_NARRATION_RE.match(s)):
            return False
        return True


    _COMMIT_RULES = (
        "You are writing the FINAL ANSWER to a research question from evidence that "
        "has already been gathered. You have NO tools — never emit tool syntax. A "
        "judge compares your answer with a strong reference and credits only claims "
        "carrying an [n] citation to the numbered evidence.\n\n"
        "SHAPE: the first words are the answer entities themselves — no preamble, no "
        "remark about evidence quality. Then a short proof section: the candidate "
        "pool, each condition applied, one line per qualifier (cited) and one line "
        "per rejected member with its cited reason — every member gets its own "
        "line, never several swept into one clause. Reproduce figures and dates "
        "VERBATIM. Name ALL qualifying members — omitting one scores as wrong. "
        "Obey any literal formatting demand in the question — sort order, "
        "comma-separated, a requested count, 'without the word X' meaning delete "
        "that word — the shape is graded too. "
        "Never say what the evidence does not contain; commit to the best-supported "
        "answer you can defend."
    )

    _REPAIR_ORDER = (
        "Your last message was not a usable final answer (it contained tool-call "
        "markup, was empty, or was a refusal). Do NOT emit tool syntax as text. "
        "Write the FINAL ANSWER now as plain prose: first words are the answer "
        "entities themselves, every factual claim followed by its [n] citation, "
        "then the short proof section. Nothing else."
    )


    def _sanitize_draft(text: str) -> str:
        return _VERIFY_MARK_RE.sub("", text or "").strip()


    def _ledger_digest(ledger: EvidenceLedger, char_cap: int = 60000) -> str:
        parts: list[str] = []
        spent = 0
        for i, row in enumerate(ledger.rows, start=1):
            text = (row.get("preview") or "").strip()
            if not text:
                continue
            block = f"[{i}] {row.get('title') or ''} ({row.get('url') or ''})\n{text}"
            if spent + len(block) > char_cap:
                break
            spent += len(block)
            parts.append(block)
        return "\n\n".join(parts)


    _FURNITURE_RE = re.compile(
        r"^\s*(?:share|search|home|menu|subscribe|sign\s*in|log\s*in|newsletter|"
        r"advertisement|cookie|skip to|follow us|read more|related|tags?|categories?|"
        r"privacy|terms|contact|about us|navigation|toggle)\b", re.I)
    _SRC_FOOTNOTE_RE = re.compile(r"\[\s*\d{1,3}\s*\]")
    _MD_LINK_RE = re.compile(r"\]\(")
    _BARE_URL_RE = re.compile(r"(?<!\]\()https?://")
    _SENTENCEY_RE = re.compile(r"[.!?]\s|[.!?]$|\b(?:is|was|were|are|has|have|had|"
                               r"reported|announced|released|won|ranked|totall?ed)\b", re.I)


    def _informative_lead(preview: str, limit: int = 280) -> str:
        kept: list[str] = []
        broke = False
        for chunk in re.split(r"(?<=[.!?])\s+|\n+", _SRC_FOOTNOTE_RE.sub("", preview or "")):
            seg = " ".join(chunk.split())
            if len(seg) < 30 or len(seg) > 400:
                if kept:
                    broke = True
                    break
                continue
            if _SENTENCEY_RE.search(seg) is None:
                if kept:
                    broke = True
                    break
                continue
            if _FURNITURE_RE.match(seg) and not re.search(r"\d", seg):
                if kept:
                    broke = True
                    break
                continue
            if seg.startswith(("*", "|", "↑", "#")):
                if kept:
                    broke = True
                    break
                continue
            links = len(_MD_LINK_RE.findall(seg)) + len(_BARE_URL_RE.findall(seg))
            if links and links * 110 >= len(seg):
                if kept:
                    broke = True
                    break
                continue
            kept.append(seg)
            if sum(len(k) for k in kept) >= limit:
                break
        else:
            pass
        out = " ".join(kept).strip()
        if len(out) > limit:
            cut = out.rfind(" ", 0, limit)
            out = out[:cut if cut > 60 else limit].rstrip(" ,;:-")
        return out


    def _deterministic_answer(question: str, ledger: EvidenceLedger) -> str:
        rows = [(i, r) for i, r in enumerate(ledger.rows, start=1)
                if (r.get("preview") or "").strip()]
        if not rows:
            return ""
        out = ["Best-supported findings from the sources retrieved:"]
        picked = 0
        for i, r in rows:
            if picked >= 6:
                break
            lead = _informative_lead(r.get("preview") or "")
            if not lead:
                continue
            title = (r.get("title") or "").strip()
            out.append(f"- {title + ': ' if title else ''}{lead} [{i}]")
            picked += 1
        if picked == 0:
            for i, r in rows[:4]:
                lead = " ".join((r.get("preview") or "").split())[:280]
                if lead:
                    out.append(f"- {lead} [{i}]")
            if len(out) == 1:
                return ""
        return "\n".join(out)


    QUOTE_SYNTH_TIMEOUT_S = 42.0
    QUOTE_SYNTH_MIN_BUDGET_S = 30.0
    QUOTE_SYNTH_MIN_QUOTES = 2
    QUOTE_TABLE_CHARS = 1400


    def _quote_table(ledger: EvidenceLedger) -> str:
        parts = []
        for i, row in enumerate(ledger.rows, start=1):
            text = row.get("text") or ""
            for a, b in (row.get("retained") or []):
                excerpt = text[max(0, int(a)):int(b)][:QUOTE_TABLE_CHARS].strip()
                if excerpt:
                    parts.append(f"[{i}] {row.get('title') or row.get('url') or ''}\n{excerpt}")
        return "\n\n".join(parts)


    def _retained_count(ledger: EvidenceLedger) -> int:
        return sum(len(r.get("retained") or []) for r in ledger.rows)


    async def _write_from_digest(question: str, ledger: EvidenceLedger, deadline: float) -> str:
        left = deadline - monotonic()
        if left < 14.0:
            return ""
        digest = _ledger_digest(ledger)
        if not digest:
            return ""
        convo = [{"role": "system", "content": _COMMIT_RULES},
                 {"role": "user", "content": (
                     f"Question: {question}\n\nNumbered evidence you gathered (cite "
                     f"facts by these [n]):\n\n{digest}\n\n"
                     "Write the FINAL ANSWER now from this evidence. Plain prose, no "
                     "tool syntax. First words are the answer entities; every factual "
                     "claim carries its [n]; then the short proof section (pool, "
                     "conditions, qualifiers, exclusions).")}]
        async def _one(lane: str, model: str, budget: float) -> str:
            _p0 = _upstream(lane, model)
            payload = None
            for _p in ((_p0, None) if _p0 is not None else (None,)):
                try:
                    payload = await llm_chat(
                        provider=lane, model=model, messages=convo,
                        temperature=0.15, max_output_tokens=2600,
                        timeout=budget, thinking=_least_think(lane, model),
                        provider_extra=_p,
                    )
                    break
                except Exception:
                    if _p is None:
                        raise
                    continue
            _spend_note(payload)
            llm = getattr(payload, "llm", None)
            text = (getattr(llm, "raw_text", None) or "").strip()
            if not text:
                choices = getattr(llm, "choices", None) or []
                if choices:
                    c = getattr(choices[0].message, "content", None)
                    if isinstance(c, str):
                        text = c.strip()
            return text

        lanes = ((LLM_LANE_A, LOOP_MODEL_A), (LLM_LANE_B, LOOP_MODEL_B))
        for i, lane_model in enumerate(lanes):
            left = deadline - monotonic()
            if left < 14.0:
                return ""
            budget = min(RESCUE_TIMEOUT_S, left - DIGEST_TAIL_S)
            if i == 0:
                budget = min(budget, max(12.0, left - 14.0 - DIGEST_TAIL_S))
            if budget < 8.0:
                return ""
            try:
                text = await _one(lane_model[0], lane_model[1], budget)
            except Exception:
                continue
            if _is_usable_answer(text):
                return text
        return ""


    async def _knowledge_resort(question: str, deadline: float) -> str:
        left = deadline - monotonic()
        if left < 12.0:
            return ""
        try:
            return await _chat_simple(
                LLM_LANE_A, RESORT_MODEL,
                ("Expert researcher. Best definitive answer with concrete entities, "
                 "numbers, dates. Never refuse."),
                question, max_tokens=2600, timeout=min(45.0, left - 4.0))
        except Exception:
            return ""


    async def _schema_output(question: str, answer: str, schema, deadline: float) -> object | None:
        ask = ("Convert the answer to a JSON value valid under the schema. Output "
               "ONLY the JSON value.\n\n"
               f"Schema:\n{json.dumps(schema)}\n\nQuestion:\n{question}\n\n"
               f"Answer:\n{answer[:14000]}")
        for lane, model in ((LLM_LANE_A, SCHEMA_MODEL),
                            (LLM_LANE_A, RESORT_MODEL),
                            (LLM_LANE_B, LOOP_MODEL_B)):
            left = deadline - monotonic()
            if left < 12.0:
                break
            try:
                raw = await _chat_simple(lane, model,
                                         "You output strictly valid JSON.", ask,
                                         max_tokens=3400, timeout=min(45.0, left - 4.0))
                raw = re.sub(r"^```(?:json)?\s*|\s*```$", "", raw.strip(),
                             flags=re.I | re.M).strip()
                value = json.loads(raw)
                if _matches_schema_shape(value, schema):
                    return value
                if isinstance(value, dict) and len(value) == 1:
                    inner = list(value.values())[0]
                    if _matches_schema_shape(inner, schema):
                        return inner
            except Exception:
                continue
        return None


    def _schema_kind(schema) -> str:
        if not isinstance(schema, dict):
            return ""
        kind = schema.get("type")
        if isinstance(kind, list):
            kind = kind[0] if kind else None
        if kind is None:
            for key in ("anyOf", "oneOf", "allOf"):
                branch = schema.get(key)
                if isinstance(branch, list):
                    for sub in branch:
                        got = _schema_kind(sub)
                        if got:
                            return got
            if isinstance(schema.get("properties"), dict):
                return "object"
            if isinstance(schema.get("enum"), list):
                return "string"
            return ""
        return str(kind)


    def _matches_schema_shape(value, schema) -> bool:
        kind = _schema_kind(schema)
        if not kind:
            return True
        if kind == "array":
            return isinstance(value, list)
        if kind == "object":
            return isinstance(value, dict)
        if kind == "string":
            return isinstance(value, str)
        if kind == "integer":
            return isinstance(value, int) and not isinstance(value, bool)
        if kind == "number":
            return isinstance(value, (int, float)) and not isinstance(value, bool)
        if kind == "boolean":
            return isinstance(value, bool)
        if kind == "null":
            return value is None
        return True


    _NUM_IN_TEXT_RE = re.compile(r"-?\d[\d,]*(?:\.\d+)?")


    _DIGEST_LEAD_RE = re.compile(r"^\s*Best-supported findings|^\s*sources retrieved:", re.I)
    _DIGEST_NOISE_RE = re.compile(r"\[slice \d+:\d+\]|https?://\S+")
    _VALUE_MAX_CHARS = 90


    def _undigest_for_schema(basis: str) -> str:
        if not basis:
            return ""
        text = _DIGEST_NOISE_RE.sub(" ", basis)
        out = []
        for raw in text.split("\n"):
            line = raw.strip().lstrip("-*• ").strip()
            if not line or _DIGEST_LEAD_RE.match(line):
                continue
            if ":" in line:
                head, _, tail = line.partition(":")
                line = tail.strip() if 0 < len(tail.strip()) <= _VALUE_MAX_CHARS else head.strip()
            if not line or len(line) > _VALUE_MAX_CHARS:
                continue
            if line.count(" ") > 8:
                continue
            if line not in out:
                out.append(line)
            if len(out) >= 6:
                break
        return "\n".join(out)


    def _enum_from_answer(answer: str, enum: list):
        low = (answer or "").lower()
        for opt in enum:
            if isinstance(opt, str) and re.search(r"\b" + re.escape(opt.lower()) + r"\b", low):
                return opt
        return enum[0]


    def _follow_union(answer: str, schema, depth: int):
        for key in ("anyOf", "oneOf", "allOf"):
            branch = schema.get(key)
            if isinstance(branch, list) and branch:
                for sub in branch:
                    if isinstance(sub, dict) and sub.get("type") != "null":
                        return True, _coerce_to_schema(answer, sub, depth + 1)
        return False, None


    def _array_from_answer(answer: str, schema, depth: int):
        items = schema.get("items") or {}
        parts = [p.strip(" -*\t") for p in re.split(r"[\n;]|,(?![^(]*\))", answer or "")]
        parts = [p[:400] for p in parts if p][:20]
        if not parts:
            parts = [answer[:400]]
        return [_coerce_to_schema(p, items, depth + 1) for p in parts]


    def _object_from_answer(answer: str, schema, depth: int):
        props = schema.get("properties") or {}
        required = schema.get("required") or list(props.keys())
        out = {}
        for key in required:
            out[key] = _coerce_to_schema(answer, props.get(key) or {}, depth + 1)
        return out


    def _number_from_answer(answer: str, kind: str):
        found = _NUM_IN_TEXT_RE.search(_CITE_NUM_RE.sub(" ", answer or ""))
        if found is None:
            return 0
        val = found.group(0).replace(",", "")
        try:
            return int(val) if kind == "integer" else float(val)
        except Exception:
            return 0


    def _coerce_to_schema(answer: str, schema, depth: int = 0):
        if depth > 4 or not isinstance(schema, dict):
            return answer[:400]
        enum = schema.get("enum")
        if isinstance(enum, list) and enum:
            return _enum_from_answer(answer, enum)
        kind = _schema_kind(schema)
        if not kind:
            found, coerced = _follow_union(answer, schema, depth)
            if found:
                return coerced
            kind = "string"
        if kind == "array":
            return _array_from_answer(answer, schema, depth)
        if kind == "object":
            return _object_from_answer(answer, schema, depth)
        if kind in ("number", "integer"):
            return _number_from_answer(answer, kind)
        if kind == "boolean":
            return not re.match(r"\s*(no\b|false\b|none\b)", (answer or ""), re.I)
        return (answer or "")[:400]


    _NARRATION_LEAD_RE = re.compile(
        r"^\s*(?:based on (?:my|the)\b|now (?:i|that i)\b|i (?:now )?(?:have|was|am|need|will|can)\b|"
        r"i(?:'ll|'ve|'m)\b|let me\b|let's\b|first,? i\b|having (?:now )?\w+\b|"
        r"okay\b|alright\b|to answer this\b|my research\b)", re.IGNORECASE)
    _ABBREV_TAIL_RE = re.compile(r"(?:\b[A-Z]|\b(?:Inc|Ltd|Co|No|vs|St|Dr|Mr|Ms|Mt|Jr|Sr|etc|e\.g|i\.e))\.$")


    def _strip_lead_narration(text: str) -> str:
        t = (text or "").strip()
        if not t:
            return t
        for _ in range(2):
            parts = re.split(r"(?<=[.!?])\s+", t, maxsplit=1)
            if len(parts) != 2:
                break
            head, rest = parts[0], parts[1].strip()
            if _CITE_NUM_RE.search(head):
                break
            if _NARRATION_LEAD_RE.match(head) is None:
                break
            if len(head.split()) < 4 or _ABBREV_TAIL_RE.search(head) is not None:
                break
            if len(rest) < 120 or _CITE_NUM_RE.search(rest) is None:
                break
            t = rest
        return t


    def _cap(text: str) -> str:
        t = (text or "").strip()
        if len(t) > ANSWER_CHAR_CAP:
            return t[:ANSWER_CHAR_CAP - 16] + " …"
        return t


    async def query(query: Query) -> Response:
        question = (query.text or "").strip()
        if not question:
            return _blank_question_reply()
        try:
            return await InquiryOrchestrator(query, question).run()
        except Exception:
            return _best_effort_reply(question, 500)


    class InquiryOrchestrator:

        def __init__(self, query: Query, question: str) -> None:
            self.query = query
            self.question = question
            self.deadline = 0.0
            self.draft = ""
            self.brief = ""
            self.ledger = None
            self.answer = ""
            self.messages: list[dict] = []
            self.citations: list = []
            self.text = ""

        async def run(self) -> Response:
            self.deadline = monotonic() + WALL_BUDGET_S
            await self._capture_budget()
            await self._maybe_brief()
            self.ledger = EvidenceLedger()
            self.answer = ""
            self.messages = []
            await self._research()
            await self._maybe_audit()
            await self._maybe_window()
            await self._maybe_corroborate()
            await self._fallback_rungs()
            self._harvest_refs()
            self._finalize()
            if self.query.output_schema is not None:
                return await self._schema_response()
            return self._text_response()

        async def _capture_budget(self) -> None:
            try:
                info = await tooling_info(timeout=10.0)
                _spend_note(info)
            except Exception:
                pass

        async def _maybe_brief(self) -> None:
            try:
                if _spend_left() >= BRIEF_MIN_USD and _clock_left(self.deadline) > _BRIEF_TIME_FLOOR_S:
                    self.draft, self.brief = await _knowledge_brief(self.question)
            except Exception:
                self.brief = ""

        async def _research(self) -> None:
            try:
                self.answer, self.messages = await _loop(
                    self.question, self.brief, self.ledger, self.deadline, MAX_TURNS)
            except Exception:
                self.answer = ""

        async def _take_if_usable(self, should_run, producer) -> None:
            try:
                if should_run():
                    patched = await producer()
                    if _is_usable_answer(patched):
                        self.answer = patched
            except Exception:
                pass

        async def _maybe_audit(self) -> None:
            await self._take_if_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _clock_left(self.deadline) > _AUDIT_TIME_FLOOR_S
                         and _spend_left() >= AUDIT_MIN_USD),
                lambda: _audit_patch(self.question, self.answer, self.messages,
                                     self.ledger, self.deadline),
            )

        async def _maybe_window(self) -> None:
            await self._take_if_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _clock_left(self.deadline) > _WINDOW_TIME_FLOOR_S),
                lambda: _window_repair(self.question, self.answer, self.messages,
                                       self.ledger, self.deadline),
            )

        async def _maybe_corroborate(self) -> None:
            await self._take_if_usable(
                lambda: (_is_usable_answer(self.answer)
                         and _clock_left(self.deadline) > _CORROB_TIME_FLOOR_S
                         and _spend_left() >= AUDIT_MIN_USD),
                lambda: _corroborate(self.question, self.answer, self.messages,
                                     self.ledger, self.deadline),
            )

        async def _fallback_rungs(self) -> None:
            if not _is_usable_answer(self.answer) and self.ledger.rows:
                try:
                    rescued = await _write_from_digest(self.question, self.ledger, self.deadline)
                    if _is_usable_answer(rescued):
                        self.answer = rescued
                except Exception:
                    pass
            if not _is_usable_answer(self.answer) and self.ledger.rows:
                det = _deterministic_answer(self.question, self.ledger)
                if _is_usable_answer(det):
                    self.answer = det
            if not _is_usable_answer(self.answer):
                fallback = _sanitize_draft(self.draft) or await _knowledge_resort(self.question, self.deadline)
                if _is_usable_answer(fallback):
                    self.answer = fallback

        def _harvest_refs(self) -> None:
            try:
                self.citations = _citations_for(self.answer, self.ledger)
            except Exception:
                self.citations = []

        def _finalize(self) -> None:
            self.answer = _normalize_brackets(self.answer)
            self.answer = _strip_lead_narration(self.answer)
            self.answer = _answer_line_only(self.answer, self.question)
            self.text = _cap(self.answer) or f"{_BEST_EFFORT_PREFIX}{self.question[:400]}"

        async def _schema_response(self) -> Response:
            query = self.query
            question = self.question
            answer = self.answer
            ledger = self.ledger
            deadline = self.deadline
            citations = self.citations
            structured = None
            try:
                structured = await _schema_output(question, answer, query.output_schema, deadline)
            except Exception:
                structured = None
            if structured is not None:
                try:
                    structured = _verbatim_structured(structured, ledger)
                except Exception:
                    pass
                try:
                    return Response(output=structured, citations=citations or None)
                except Exception:
                    structured = None
            basis = answer if _is_usable_answer(answer) else ""
            if not basis:
                basis = _deterministic_answer(question, ledger)
            if not basis or _STUB_ANSWER_RE.match(basis.strip()):
                basis = question[:400]
            if basis is not answer:
                try:
                    salvaged = await _schema_output(question, basis, query.output_schema,
                                                    deadline)
                except Exception:
                    salvaged = None
                if salvaged is not None:
                    try:
                        return Response(output=salvaged, citations=citations or None)
                    except Exception:
                        pass
            if basis is not answer:
                cleaned = _undigest_for_schema(basis)
                basis = cleaned if cleaned else ""
            try:
                forced = _coerce_to_schema(_cap(basis), query.output_schema)
                return Response(output=forced, citations=citations or None)
            except Exception:
                try:
                    return Response(output=_cap(basis)[:2000],
                                    citations=citations or None)
                except Exception:
                    pass
            return self._text_response()

        def _text_response(self) -> Response:
            try:
                return Response(text=self.text, citations=self.citations or None)
            except Exception:
                return Response(text=self.text)

    return query

_basil_surveyor_query_entry = _compose_basil_surveyor_entry()


_ANALYTICAL_ROUTE_TERMS = (
    "compare", "difference", "calculate", "ratio", "percentage",
    "percent", "sum", "average", "median", "highest", "lowest",
    "largest", "smallest", "rank", "ordered", "sort", "filter",
    "exclude", "including only", "only those", "greater than",
    "less than", "at least", "at most", "between", "table",
    "dataset", "csv", "json", "statistics", "mintage",
)
_DIRECT_ROUTE_TERMS = (
    "who is", "what is", "when did", "where is", "which",
    "name the", "identify the", "give the", "list the",
)
_DIRECT_ANALYTICAL_BLOCK_TERMS = (
    "compare", "difference", "calculate", "ratio", "percentage",
    "percent", "sum", "average", "median", "highest", "lowest",
    "rank", "ordered", "sort", "greater than", "less than",
    "at least", "at most", "between",
)
_SHORT_SCHEMA_FIELD_CAP = 2
_SHORT_QUESTION_CHAR_CAP = 900


def _count_schema_properties(schema) -> int:
    if not isinstance(schema, dict):
        return 1
    properties = schema.get("properties")
    if isinstance(properties, dict):
        return len(properties)
    if schema.get("type") in {"array", "object"}:
        return 1
    return 1


def _schema_field_count(query: Query) -> int:
    schema = getattr(query, "output_schema", None)
    if schema is None:
        return 0
    return _count_schema_properties(schema)


def _contains_any(text: str, terms: tuple[str, ...]) -> bool:
    return any(term in text for term in terms)


def _choose_clear_branch(query: Query) -> str:
    text = (getattr(query, "text", "") or "").strip()
    lowered = text.lower()
    field_count = _schema_field_count(query)

    if field_count == 0:
        return "BasilSurveyor"
    if field_count <= _SHORT_SCHEMA_FIELD_CAP and len(text) <= _SHORT_QUESTION_CHAR_CAP and not _contains_any(lowered, _ANALYTICAL_ROUTE_TERMS):
        return "BasilSurveyor"
    if field_count <= _SHORT_SCHEMA_FIELD_CAP and _contains_any(lowered, _DIRECT_ROUTE_TERMS) and not _contains_any(
        lowered,
        _DIRECT_ANALYTICAL_BLOCK_TERMS,
    ):
        return "BasilSurveyor"
    if field_count >= 3:
        return "ZephyrNotary"
    if _contains_any(lowered, _ANALYTICAL_ROUTE_TERMS):
        return "ZephyrNotary"
    return "ZephyrNotary"


class ZephyrNotary:
    async def __call__(self, query: Query) -> Response:
        return await _zephyr_notary_query_entry(query)


class BasilSurveyor:
    async def __call__(self, query: Query) -> Response:
        return await _basil_surveyor_query_entry(query)


class _ClearBranchDispatcher:
    def pair_for(self, selected: str):
        if selected == "ZephyrNotary":
            return _CLEAR_PRIMARY_AGENT, _CLEAR_SECONDARY_AGENT
        return _CLEAR_SECONDARY_AGENT, _CLEAR_PRIMARY_AGENT

    async def dispatch(self, query: Query) -> Response:
        first, second = self.pair_for(_choose_clear_branch(query))
        try:
            return await first(query)
        except Exception:
            return await second(query)


_CLEAR_PRIMARY_AGENT = ZephyrNotary()
_CLEAR_SECONDARY_AGENT = BasilSurveyor()
_CLEAR_DISPATCHER = _ClearBranchDispatcher()
_CANDIDATE_BRANCH_CLASS_NAMES = ("ZephyrNotary", "BasilSurveyor")
_CANDIDATE_ROUTE_FUNCTION = "_choose_clear_branch"


@entrypoint("query")
async def query(query: Query) -> Response:
    return await _CLEAR_DISPATCHER.dispatch(query)

