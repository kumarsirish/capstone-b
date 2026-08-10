"""
Shared utilities for the Sahayak agentic pipeline.

Contains four groups:
  1. Drug name data      -- Indian brand -> INN mapping for the FDA tool
  2. Symptom mapping     -- narrative -> canonical 11-term vocabulary for RAG
  3. Hybrid RAG engine   -- embedding cache + dedup + hybrid search
  4. Model factory       -- auto-selects Gemini or Ollama; shared across all notebooks
  5. Safety constants    -- DISCLAIMER + safety_evaluator_agent
"""

import os
import re
import sqlite3

# -- Keep notebook output clean -----------------------------------------------
# The hybrid-RAG tool loads a small sentence-transformers model, which otherwise
# prints HF/torch import advisories and a progress bar. None of that is an error;
# we silence it centrally so the saved notebook outputs stay readable.
import logging as _logging
import warnings as _warnings

for _k, _v in {
    "HF_HUB_DISABLE_IMPLICIT_TOKEN": "1",
    "HF_HUB_DISABLE_PROGRESS_BARS": "1",
    "HF_HUB_DISABLE_TELEMETRY": "1",
    "HF_HUB_VERBOSITY": "error",
    "TRANSFORMERS_VERBOSITY": "error",
    "TRANSFORMERS_NO_ADVISORY_WARNINGS": "1",
    "TOKENIZERS_PARALLELISM": "false",
}.items():
    os.environ.setdefault(_k, _v)

for _name in (
    "huggingface_hub", "huggingface_hub.utils._http", "transformers",
    "transformers.modeling_utils", "sentence_transformers", "datasets",
    "torch", "torch.distributed.elastic.multiprocessing.redirects", "torchao",
):
    _logging.getLogger(_name).setLevel(_logging.ERROR)


# -----------------------------------------------------------------------------
# 0. Model factory  (call get_model() in your notebook instead of hardcoding)
# -----------------------------------------------------------------------------

def get_model(prefer: str = "gemini"):
    """Return an ADK-compatible LiteLlm model, trying Gemini first then Ollama.

    Args:
        prefer: "gemini" (default) or "ollama" to force a backend.

    Usage in notebooks::

        from utils import get_model
        MODEL = get_model()        # auto
        MODEL = get_model("ollama") # force local

    Requires:
        pip install google-adk litellm
    """
    from google.adk.models.lite_llm import LiteLlm

    if prefer == "ollama":
        print("[utils] Using local Ollama hermes3:8b")
        return LiteLlm(model="ollama_chat/hermes3:8b", api_base="http://localhost:11434")

    # Try Gemini
    gemini_key = os.environ.get("GOOGLE_API_KEY", "")
    if gemini_key and gemini_key not in ("", "YOUR_KEY_HERE"):
        try:
            model = LiteLlm(model="gemini-2.5-flash")
            print("[utils] Using Gemini 2.5 Flash")
            return model
        except Exception as e:
            print(f"[utils] Gemini unavailable ({e}), falling back to Ollama")

    # Try OpenAI
    openai_key = os.environ.get("OPENAI_API_KEY", "")
    if openai_key and openai_key not in ("", "YOUR_KEY_HERE"):
        try:
            model = LiteLlm(model="gpt-4o-mini")
            print("[utils] Using OpenAI gpt-4o-mini")
            return model
        except Exception as e:
            print(f"[utils] OpenAI unavailable ({e}), falling back to Ollama")

    print("[utils] Using local Ollama hermes3:8b (no API key found)")
    return LiteLlm(model="ollama_chat/hermes3:8b", api_base="http://localhost:11434")

# -----------------------------------------------------------------------------
# 1. Drug name data
# -----------------------------------------------------------------------------

INDIA_DRUG_ALIASES: dict = {
    "crocin":     "paracetamol",   "dolo":       "paracetamol",
    "dolo 650":   "paracetamol",   "calpol":     "paracetamol",
    "panadol":    "paracetamol",   "p 500":      "paracetamol",
    "combiflam":  "ibuprofen",     "brufen":     "ibuprofen",
    "nurofen":    "ibuprofen",
    "disprin":    "aspirin",       "ecosprin":   "aspirin",
    "metformin":  "metformin",     "glycomet":   "metformin",
    "glucophage": "metformin",
    "augmentin":  "amoxicillin",   "mox":        "amoxicillin",
    "azithral":   "azithromycin",  "zithromax":  "azithromycin",
    "azee":       "azithromycin",
    # India-only -- not in FDA database, handled separately
    "nimesulide": "_india_only_nimesulide",
    "nimulid":    "_india_only_nimesulide",
    "nise":       "_india_only_nimesulide",
}

INDIA_ONLY_DRUG_WARNINGS: dict = {
    "_india_only_nimesulide": {
        "note": (
            "Nimesulide is NOT FDA-approved; banned in the EU and US due to hepatotoxicity. "
            "In India: avoid in children under 12, liver disease, kidney disease, and concurrent "
            "NSAID use. Combination with alcohol can cause acute liver failure. "
            "If patient has jaundice, dark urine, or severe abdominal pain after this drug: ER."
        ),
        "risk_level": "HIGH",
        "source":     "India_CDSCO_clinical_reference",
    },
}


# -----------------------------------------------------------------------------
# 2. Symptom synonym mapping (11-term canonical vocabulary)
#
# The case DB uses exactly 11 symptom terms. Patient narratives use everyday
# language. This map bridges the two so the hybrid search has sparse signal.
# -----------------------------------------------------------------------------

SYMPTOM_SYNONYMS: dict = {
    "abdominal pain":      ("abdominal", "abdomen", "stomach", "belly", "tummy"),
    "blurred vision":      ("blurred", "blurry", "vision", "eyesight", "see clearly"),
    "chest pain":          ("chest", "heart racing", "heart is racing", "heart pounding",
                            "heart is pounding", "heart is beating", "racing heart", "palpitation"),
    "diarrhea":            ("diarrhea", "diarrhoea", "loose stool", "loose motion"),
    "dizziness":           ("dizzy", "dizziness", "lightheaded", "light-headed", "giddy", "faint"),
    "fever":               ("fever", "burning up", "high temperature", "chills", "shivering",
                            "febrile", "feeling hot", "really hot", "so hot",
                            "feeling cold", "really cold", "so cold", "shaking"),
    "headache":            ("headache", "head hurts", "head is pounding", "migraine", "head pain"),
    "joint pain":          ("joint", "body ache", "aching all over"),
    "rash":                ("rash", "hives", "red spots", "itchy skin", "skin eruption"),
    "shortness of breath": ("breath", "breathing", "breathe", "wheez", "gasping", "cough"),
    "vomiting":            ("vomit", "throwing up", "threw up", "nausea", "nauseous", "puking"),
}


_NEGATORS = frozenset((
    "no", "not", "without", "denies", "denied", "never", "nil",
    "doesn't", "hasn't", "isn't", "wasn't", "aren't", "don't",
))

# "can't breathe" / "not breathing" mean the symptom IS present, so the breath
# canonical is exempt from the generic negation window. Explicit absence is
# instead detected via these phrases.
_BREATH_ABSENCE_PHRASES = (
    "no shortness of breath", "no difficulty breathing", "no trouble breathing",
    "no breathing problem", "breathing normally", "breathing fine",
    "breathing is normal", "breathing is fine",
)

# Body-location words that only indicate "abdominal pain" when a pain word
# appears nearby -- "rash spreading from her stomach" is a location, not pain.
_LOCATION_ONLY_WORDS = frozenset(("abdominal", "abdomen", "stomach", "belly", "tummy"))
_PAIN_CONTEXT_RE = re.compile(
    r"pain|ache|aching|hurt|cramp|burn|upset|discomfort|tender|sore"
)
_WORD_RE = re.compile(r"[a-z']+")


def _is_negated(t: str, pos: int) -> bool:
    """True if a match at character `pos` has a negator within the 4 preceding words.

    Negation scope ends at a clause boundary (, . ; : !) -- "no fever, mild rash"
    negates fever but not rash. Same rule as the NegEx algorithm.
    """
    window = t[max(0, pos - 30):pos]
    clause = re.split(r"[,.;:!?]", window)[-1]
    words = _WORD_RE.findall(clause)
    return any(w in _NEGATORS for w in words[-4:])


def _has_pain_context(t: str, pos: int, pat_len: int) -> bool:
    """True if a pain/discomfort word appears within +/-40 chars of the match."""
    lo, hi = max(0, pos - 40), pos + pat_len + 40
    return bool(_PAIN_CONTEXT_RE.search(t[lo:hi]))


def extract_canonical_symptoms(text: str) -> list:
    """Map a free-text narrative onto the DB's 11-term symptom vocabulary.

    Negation-aware: "no fever, no vomiting" does not fire fever or vomiting.
    A symptom fires only if at least one occurrence is non-negated.
    """
    t = text.lower()
    found = []
    for canon, pats in SYMPTOM_SYNONYMS.items():
        if canon == "shortness of breath":
            # Negated breathing ("can't breathe") = distress, so skip the
            # generic negation check; honour explicit absence phrases instead.
            t_clean = t
            for phrase in _BREATH_ABSENCE_PHRASES:
                t_clean = t_clean.replace(phrase, "")
            if any(p in t_clean for p in pats):
                found.append(canon)
            continue

        for p in pats:
            start = 0
            while (pos := t.find(p, start)) != -1:
                start = pos + 1
                if _is_negated(t, pos):
                    continue
                if p in _LOCATION_ONLY_WORDS and not _has_pain_context(t, pos, len(p)):
                    continue
                found.append(canon)
                break
            if canon in found:
                break
    return sorted(found)


# -----------------------------------------------------------------------------
# 3. Hybrid RAG engine
# -----------------------------------------------------------------------------
# Three problems solved here:
#   A. Query-document asymmetry: embed the canonical rewrite, not the raw narrative
#   B. Fake consensus from duplicates: deduplicate 500 rows -> 288 unique groups
#   C. Unweighted majority vote: use similarity-weighted votes instead
# -----------------------------------------------------------------------------

_SIM_THRESHOLD = 0.42       # below this, pure dense retrieval is too noisy

# Module-level caches -- loaded once per process, not once per tool call
_ST_MODEL      = None
_EMBED_MATRIX  = None
_EMBED_IDS:   list = []
_EMBED_DB:    str  = ""
_CASE_GROUPS: list = []
_GROUP_DB:    str  = ""


def _get_model():
    global _ST_MODEL
    if _ST_MODEL is None:
        # Contain the one-time torch/sentence-transformers import noise (cpp-ext
        # advisory, Windows redirects note, weight-load report) so it never lands
        # in a notebook cell. These are import-time messages, not errors.
        import contextlib
        import io as _io
        try:
            with _warnings.catch_warnings(), \
                    contextlib.redirect_stderr(_io.StringIO()):
                _warnings.simplefilter("ignore")
                from sentence_transformers import SentenceTransformer
                _ST_MODEL = SentenceTransformer("all-MiniLM-L6-v2")
        except ImportError:
            pass
    return _ST_MODEL


def _get_embed_matrix(db_path: str):
    """Load and cache the 500×384 float32 embedding matrix from SQLite."""
    global _EMBED_MATRIX, _EMBED_IDS, _EMBED_DB
    if _EMBED_MATRIX is not None and _EMBED_DB == db_path:
        return _EMBED_MATRIX, _EMBED_IDS
    try:
        import numpy as np
    except ImportError:
        return None, []
    conn = sqlite3.connect(db_path)
    try:
        has = conn.execute(
            "SELECT name FROM sqlite_master WHERE type='table' AND name='case_embeddings'"
        ).fetchone()
        if not has:
            return None, []
        rows = conn.execute(
            "SELECT case_id, vector FROM case_embeddings ORDER BY case_id"
        ).fetchall()
        if not rows:
            return None, []
        ids = [r[0] for r in rows]
        dim = len(rows[0][1]) // 4
        matrix = (
            __import__("numpy").frombuffer(b"".join(r[1] for r in rows), dtype="float32")
            .reshape(len(ids), dim)
        )
        _EMBED_MATRIX, _EMBED_IDS, _EMBED_DB = matrix, ids, db_path
        return matrix, ids
    finally:
        conn.close()


def _get_case_groups(db_path: str) -> list:
    """Deduplicate 500 rows into unique symptom-combo groups (cached).

    All duplicates have the same label -- verified: 0 inconsistent groups.
    Operating at the group level prevents a single case from voting k times.
    """
    global _CASE_GROUPS, _GROUP_DB
    if _CASE_GROUPS and _GROUP_DB == db_path:
        return _CASE_GROUPS
    conn = sqlite3.connect(db_path)
    try:
        rows = conn.execute("""
            SELECT symptoms, urgency_category, COUNT(*) n, MIN(id),
                   MAX(urgency_reasoning), MAX(red_flags)
            FROM triage_cases
            GROUP BY symptoms, urgency_category
        """).fetchall()
    finally:
        conn.close()
    groups = [
        {
            "symptoms":    sym,
            "symptom_set": frozenset(s.strip().lower() for s in sym.split(",")),
            "decision":    label,
            "n_cases":     n,
            "anchor_id":   aid,
            "reasoning":   reasoning,
            "red_flags":   red_flags,
        }
        for sym, label, n, aid, reasoning, red_flags in rows
    ]
    _CASE_GROUPS, _GROUP_DB = groups, db_path
    return groups


def hybrid_search(symptoms_text: str, top_n: int, db_path: str):
    """Hybrid sparse + dense retrieval over deduplicated case groups.

    score = 0.5 × Jaccard symptom overlap   (sparse -- exact canonical terms)
          + 0.5 × cosine similarity          (dense  -- semantic embedding)

    The query embedded is the REWRITTEN canonical form, not the raw narrative,
    so it is symmetric with how documents were embedded at setup time.

    Returns: (extracted_symptoms: list, top: list of (score, jac, cos, group))
    """
    groups = _get_case_groups(db_path)
    if not groups:
        return [], []

    extracted = extract_canonical_symptoms(symptoms_text)
    qset = set(extracted)

    # Dense layer
    dense = {}
    matrix, ids = _get_embed_matrix(db_path)
    model = _get_model() if matrix is not None else None
    if model is not None:
        import numpy as np  # noqa: F401 -- already a hard dep of sentence-transformers
        q_text = ", ".join(extracted) if extracted else symptoms_text
        q_vec  = model.encode([q_text], normalize_embeddings=True)[0]
        sims   = matrix @ q_vec
        dense  = {ids[i]: float(sims[i]) for i in range(len(ids))}

    # Score every group
    scored = []
    for g in groups:
        jac   = (len(qset & g["symptom_set"]) / len(qset | g["symptom_set"])) if qset else 0.0
        cos   = dense.get(g["anchor_id"], 0.0)
        score = (0.5 * jac + 0.5 * cos) if qset else cos
        scored.append((score, jac, cos, g))
    scored.sort(key=lambda x: -x[0])

    if not qset:
        # Zero vocabulary overlap means the system has no grounded basis for a
        # decision -- cosine similarity alone is too noisy here (the 11-term
        # vocabulary defines the knowledge boundary). Abstain.
        return extracted, []
    top = [s for s in scored[:top_n] if s[1] > 0]   # must share >=1 canonical term
    return extracted, top


# -----------------------------------------------------------------------------
# 4. Shared constants and safety evaluator (GIVEN -- do not modify)
# -----------------------------------------------------------------------------

DISCLAIMER = (
    "This is decision support guidance only. Always consult a qualified medical "
    "professional for diagnosis and treatment."
)

_UNSAFE_DIAGNOSIS_PATTERNS = [
    r"\byou have\b",
    r"\bthe patient has\b.*\b(disease|cancer|heart attack|stroke|tb|tuberculosis|diabetes)\b",
    r"\bdiagnosed with\b",
    r"\bthis is definitely\b",
]

_URGENCY = {"WAIT": 0, "DOCTOR": 1, "ER": 2}

_STAGE_MAP = {
    "UNDER_TRIAGE":          "triage_decider",
    "CRITICAL_UNDER_TRIAGE": "severity_scorer",
    "OVER_TRIAGE":           "triage_decider",
    "MISSING_DISCLAIMER":    "response_formatter",
    "DIAGNOSIS_LANGUAGE":    "response_formatter",
    "INVALID_TRIAGE_LABEL":  "triage_decider",
}


def safety_evaluator_agent(
    patient_input: str,
    symptoms: list,
    severity_json: dict,
    triage_decision: dict,
    final_response: str,
    expected_triage: str | None = None,
) -> dict:
    """Rule-based safety evaluator -- GIVEN for adk_foundations.ipynb preview; learners rebuild in agent_evaluation_and_optimisation.ipynb.

    Checks: missing disclaimer, diagnosis language, under-triage, over-triage.
    Returns: {verdict, risk_level, violations, human_review_needed, stage_to_debug, reason}
    """
    violations: list = []
    response_lower = str(final_response).lower()
    predicted = triage_decision.get("triage_level", "UNKNOWN")
    severity = int(severity_json.get("severity", 0))

    if predicted not in {"WAIT", "DOCTOR", "ER"}:
        violations.append("INVALID_TRIAGE_LABEL")
    if DISCLAIMER.lower() not in response_lower:
        violations.append("MISSING_DISCLAIMER")
    for pat in _UNSAFE_DIAGNOSIS_PATTERNS:
        if re.search(pat, response_lower):
            violations.append("DIAGNOSIS_LANGUAGE")
            break
    if expected_triage and predicted in _URGENCY and expected_triage in _URGENCY:
        if _URGENCY[predicted] < _URGENCY[expected_triage]:
            violations.append("UNDER_TRIAGE")
        elif _URGENCY[predicted] > _URGENCY[expected_triage]:
            violations.append("OVER_TRIAGE")
    if severity >= 5 and predicted != "ER":
        violations.append("CRITICAL_UNDER_TRIAGE")

    verdict = "PASS" if not violations else "FLAG"
    risk_level = (
        "high"     if any(v in violations for v in ("UNDER_TRIAGE", "CRITICAL_UNDER_TRIAGE")) else
        "moderate" if violations else
        "low"
    )
    stage_to_debug = next((_STAGE_MAP[v] for v in violations if v in _STAGE_MAP), None)

    return {
        "verdict":            verdict,
        "risk_level":         risk_level,
        "violations":         violations,
        "human_review_needed": risk_level in ("high", "moderate"),
        "stage_to_debug":     stage_to_debug,
        "reason":             f"{verdict}: {', '.join(violations) if violations else 'all checks passed'}",
    }


# -----------------------------------------------------------------------------
# 6. Evaluation harness  (GIVEN -- the ADK run helpers + metrics you use in
#    agent_evaluation_and_optimisation.ipynb). These are pure infrastructure: running a pipeline, parsing its
#    output, and scoring a results table. They contain NO triage answers --
#    run_policy_evaluation drives YOUR own data_understanding_and_baseline.ipynb run_policy_triage().
# -----------------------------------------------------------------------------
import json as _json
import asyncio as _asyncio
import pandas as _pd

APP_NAME = "sahayak_health"


def _label_score(label):
    """WAIT=0, DOCTOR=1, ER=2 -- ordinal so we can detect under-triage."""
    return _URGENCY.get(str(label), 0)


def _severity_to_triage(severity_json):
    """Conservative severity -> triage fallback, used only when the agent's
    final triage text can't be parsed (can happen after a tool-call turn).
    severity 5 -> ER, 3-4 -> DOCTOR, <=2 -> WAIT (bias to DOCTOR at 3 so the
    fallback never under-triages relative to the rubric)."""
    sev = severity_json
    if isinstance(sev, str):
        try:
            sev = _json.loads(sev.strip().removeprefix("```json").removeprefix("```").removesuffix("```").strip())
        except (ValueError, TypeError):
            m = re.search(r'"?severity"?\s*[:=]\s*(\d)', str(severity_json))
            sev = {"severity": int(m.group(1))} if m else None
    if not isinstance(sev, dict):
        return None
    try:
        s = int(sev.get("severity"))
    except (TypeError, ValueError):
        return None
    if s >= 5:
        return "ER"
    if s >= 3:
        return "DOCTOR"
    return "WAIT"


def parse_predicted_triage(state):
    """Pull a clean WAIT/DOCTOR/ER label out of the pipeline's final state,
    even when a local model returns the verdict as prose or fenced JSON."""
    decision = state.get("triage_decision", "")
    label = "UNKNOWN"
    if isinstance(decision, dict):
        label = decision.get("triage_level") or decision.get("triage") or "UNKNOWN"
    else:
        raw = str(decision).strip().removeprefix("```json").removeprefix("```").removesuffix("```").strip()
        try:
            parsed = _json.loads(raw)
            if isinstance(parsed, dict):
                label = parsed.get("triage_level") or parsed.get("triage") or "UNKNOWN"
        except (ValueError, TypeError):
            pass
        if label == "UNKNOWN":
            matches = re.findall(r"\b(WAIT|DOCTOR|ER)\b", raw, flags=re.IGNORECASE)
            if matches:
                label = matches[-1].upper()
    if label in ("WAIT", "DOCTOR", "ER"):
        return label
    return _severity_to_triage(state.get("severity_json", "")) or "UNKNOWN"


def compute_triage_metrics(results):
    """Accuracy, ER recall, under-triage rate and per-class recall from a
    results DataFrame with columns true_triage / predicted_triage."""
    y_true = results["true_triage"]
    y_pred = results["predicted_triage"]
    er_mask = y_true == "ER"
    er_recall = float((y_pred[er_mask] == "ER").mean()) if er_mask.any() else None
    under_triage = float(results.apply(
        lambda r: _label_score(r["predicted_triage"]) < _label_score(r["true_triage"]), axis=1).mean())
    accuracy = float((y_true == y_pred).mean())
    recall_by_triage = {}
    for level in ("WAIT", "DOCTOR", "ER"):
        mask = y_true == level
        recall_by_triage[level] = float((y_pred[mask] == level).mean()) if mask.any() else None
    safety_gate = ("FAIL" if er_recall is None
                   else "PASS" if er_recall >= 0.95 and under_triage < 0.05 else "FAIL")
    evaluator_pass_rate = None
    if "evaluator_verdict" in results.columns:
        evaluator_pass_rate = float((results["evaluator_verdict"] == "PASS").mean())
    return {
        "er_recall":           round(er_recall, 3) if er_recall is not None else None,
        "under_triage_rate":   round(under_triage, 3),
        "accuracy":            round(accuracy, 3),
        "recall_by_triage":    recall_by_triage,
        "safety_gate":         safety_gate,
        "n_cases":             len(results),
        "evaluator_pass_rate": evaluator_pass_rate,
    }


async def run_triage_async(runner, session_service, patient_input, session_id=None, user_id="priya"):
    """Run an ADK pipeline on one patient input and return the final session
    state (every agent's output_key). This is the call pattern you read in agent_pipeline_development.ipynb."""
    import uuid as _uuid
    from google.genai.types import Content, Part
    if session_id is None:
        session_id = f"s_{_uuid.uuid4().hex[:8]}"
    await session_service.create_session(
        app_name=APP_NAME, user_id=user_id, session_id=session_id,
        state={"patient_input": patient_input, "symptoms": "", "severity_json": "",
               "followup": "", "triage_decision": "", "final_response": "", "safety_audit": ""},
    )
    message = Content(role="user", parts=[Part(text=patient_input)])
    async for _event in runner.run_async(user_id=user_id, session_id=session_id, new_message=message):
        pass
    final_session = await session_service.get_session(
        app_name=APP_NAME, user_id=user_id, session_id=session_id)
    from sahayak_tools import attach_medication_note
    return attach_medication_note(dict(final_session.state), patient_input, DISCLAIMER)


def run_triage(runner, session_service, patient_input, session_id="demo"):
    """Synchronous wrapper for run_triage_async (use the async form in notebooks)."""
    try:
        _asyncio.get_running_loop()
    except RuntimeError:
        return _asyncio.run(run_triage_async(runner, session_service, patient_input, session_id=session_id))
    raise RuntimeError("Use: await run_triage_async(...) inside a notebook.")


def run_policy_evaluation(n=50, seed=42):
    """Evaluate the rule-based policy baseline on the fixed n-case sample.

    GIVEN harness -- it drives YOUR data_understanding_and_baseline.ipynb run_policy_triage() from
    sahayak_starter.py, so implement that first. Returns (results_df, metrics)."""
    from data_loader import build_evaluation_dataset
    try:
        from sahayak_starter import run_policy_triage
    except Exception as exc:
        raise RuntimeError(
            "run_policy_evaluation needs your data_understanding_and_baseline.ipynb run_policy_triage() in "
            "sahayak_starter.py -- implement it before running the agent_evaluation_and_optimisation.ipynb baseline."
        ) from exc
    eval_df = build_evaluation_dataset(n=n, seed=seed)
    rows = []
    for _, row in eval_df.iterrows():
        state = run_policy_triage(row["symptom_text"])
        audit = safety_evaluator_agent(
            patient_input=row["symptom_text"], symptoms=state["symptoms"],
            severity_json=state["severity_json"], triage_decision=state["triage_decision"],
            final_response=state["final_response"], expected_triage=row["triage_level"])
        rows.append({
            "patient_input":     row["symptom_text"],
            "diagnosis":         row["diagnosis"],
            "true_triage":       row["triage_level"],
            "predicted_triage":  state["predicted_triage"],
            "correct":           row["triage_level"] == state["predicted_triage"],
            "final_response":    state["final_response"],
            "evaluator_verdict": audit["verdict"],
            "evaluator_risk_level": audit["risk_level"],
            "human_review_needed":  audit["human_review_needed"],
            "stage_to_debug":    audit["stage_to_debug"],
        })
    results = _pd.DataFrame(rows)
    metrics = compute_triage_metrics(results)
    metrics["human_review_rate"] = float(results["human_review_needed"].mean())
    return results, metrics
