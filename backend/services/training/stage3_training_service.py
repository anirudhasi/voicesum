"""
Stage 3 Training Service — DSPy optimization for Point -> Agenda Assignment.
This service manages the lifecycle of Stage 3 DSPy variants:
  Default -> Variant 001 -> Variant 002 -> ... (immutable chain via feedback)

Stage 3 Task (Step 2: Point -> Agenda Assignment):
  - Take Stage 2 enhanced points and calculate cosine similarity against all agenda details.
  - For each point, select the Top 3 matching candidate agendas.
  - Send groups of 10-20 points with their candidate agendas to the LLM/DSPy module.
  - LLM assigns each point to the correct agenda with confidence and reasoning.

Each variant is stored as an immutable JSON artifact in checkpoints/stage3/.
"""
from __future__ import annotations
import json
import uuid
import logging
import re
import os
import math
import threading
from typing import List, Dict, Any, Optional
from datetime import datetime, timezone
from pathlib import Path
import numpy as np

logger = logging.getLogger(__name__)

# Base directory for Stage 3 artifacts
STAGE3_BASE = Path('checkpoints') / 'stage3'
STAGE3_VARIANTS_FILE = STAGE3_BASE / 'variants.json'
STAGE3_HISTORY_FILE = STAGE3_BASE / 'history.json'
STAGE3_SETTINGS_FILE = STAGE3_BASE / 'settings.json'
STAGE3_FEEDBACK_FILE = STAGE3_BASE / 'feedback.json'

# Active optimization runs (in-memory)
_active_runs: Dict[str, Dict[str, Any]] = {}
_run_lock = threading.Lock()

# ─── DSPy availability check ──────────────────────────────────────────────────

DSPY_AVAILABLE = False
try:
    import dspy
    DSPY_AVAILABLE = True
except ImportError:
    logger.warning('[Stage3] dspy-ai not installed. DSPy optimization disabled.')


# ─── Stage 3 Output Schema ────────────────────────────────────────────────────

STAGE3_OUTPUT_SCHEMA = {
    'assignments': [
        {
            'point_id': 'string (matching input point_id)',
            'assigned_agenda_id': 'string (e.g. A1, A2 matching agenda reference)',
            'confidence': 'string (high | medium | low)',
            'reason': 'string (concise reason for agenda selection)',
        }
    ]
}

STAGE3_DEFAULT_INSTRUCTIONS = """You are an expert executive meeting assistant.
Given a list of meeting agendas and a batch of discussion points (each with top-3 candidate agendas retrieved by semantic similarity),
assign each discussion point to the single most appropriate agenda topic based on its core subject matter.

CRITICAL INSTRUCTIONS:
1. Every discussion point MUST be assigned to exactly one valid agenda ID from the provided agendas.
2. Consider the candidate agendas and similarity scores as strong recommendations, but choose the agenda that best matches the point's factual topic.
3. Provide a clear confidence level ("high", "medium", "low") and a brief 1-sentence reason.
4. Output MUST be valid JSON matching the schema with key "assignments".

Output schema:
{
  "assignments": [
    {
      "point_id": "point_id",
      "assigned_agenda_id": "A1",
      "confidence": "high",
      "reason": "Brief explanation of why this agenda is the best match"
    }
  ]
}"""


# ─── DSPy Signature for Stage 3 ───────────────────────────────────────────────

if DSPY_AVAILABLE:
    class Stage3AgendaAssignmentSignature(dspy.Signature):
        """Assign discussion points to the most appropriate agenda topic.

        Given a batch of enhanced discussion points (each with top-3 candidate agendas retrieved by similarity)
        and the full agenda reference list, assign each point to the best matching agenda ID with confidence and reason.
        """
        agenda_reference_json: str = dspy.InputField(
            desc='JSON array of all available agendas with agenda_id, title, and description'
        )
        points_batch_json: str = dspy.InputField(
            desc='JSON array of discussion points with point_id, enhanced_point text, speakers, and top candidate agendas'
        )
        assignments_json: str = dspy.OutputField(
            desc=(
                'Valid JSON object with key "assignments" containing an array of objects with: '
                'point_id, assigned_agenda_id, confidence, and reason'
            )
        )


# ─── Storage helpers ──────────────────────────────────────────────────────────

def _ensure_dirs():
    STAGE3_BASE.mkdir(parents=True, exist_ok=True)


def _load_json_file(path: Path, default) -> Any:
    try:
        if path.exists():
            return json.loads(path.read_text(encoding='utf-8'))
    except Exception as e:
        logger.warning(f'[Stage3] Failed to load {path}: {e}')
    return default


def _save_json_file(path: Path, data: Any):
    _ensure_dirs()
    path.write_text(json.dumps(data, indent=2, default=str, ensure_ascii=False), encoding='utf-8')


# ─── Settings ─────────────────────────────────────────────────────────────────

DEFAULT_SETTINGS: Dict[str, Any] = {
    'model_name': '',
    'optimizer': 'BootstrapFewShot',
    'num_trials': 10,
    'eval_split': 0.2,
    'bootstrap_examples': 3,
    'max_demonstrations': 4,
    'temperature': 0.0,
    'max_tokens': 2048,
    'points_per_batch': 15,
}


def load_settings() -> Dict[str, Any]:
    s = _load_json_file(STAGE3_SETTINGS_FILE, {})
    return {**DEFAULT_SETTINGS, **s}


def save_settings(settings: Dict[str, Any]):
    _save_json_file(STAGE3_SETTINGS_FILE, settings)


# ─── Variants ─────────────────────────────────────────────────────────────────

_DEFAULT_VARIANT = {
    'variant_id': 'default',
    'label': 'Default Stage 3 Prompt',
    'is_default': True,
    'parent_variant_id': None,
    'created_at': '2024-01-01T00:00:00+00:00',
    'optimizer': '—',
    'model': '—',
    'training_batch_count': 0,
    'validation_batch_count': 0,
    'feedback_count': 0,
    'artifact_path': None,
    'status': 'done',
    'instructions': STAGE3_DEFAULT_INSTRUCTIONS,
    'scores': {
        'overall': 0.0,
        'accuracy': 0.0,
        'candidate_validity': 0.0,
        'json_validity': 0.0,
        'schema_validity': 0.0,
    },
    'improvement_over_baseline': None,
    'is_best': False,
}


def get_all_variants() -> List[Dict[str, Any]]:
    """Return all Stage 3 variants including the default baseline with exact prompt instructions."""
    variants = _load_json_file(STAGE3_VARIANTS_FILE, [])
    non_defaults = [v for v in variants if not v.get('is_default')]
    if non_defaults:
        best = max(non_defaults, key=lambda v: (v.get('scores', {}) or {}).get('overall', 0))
        for v in variants:
            v['is_best'] = v.get('variant_id') == best.get('variant_id')
    return [dict(_DEFAULT_VARIANT)] + [v for v in variants if not v.get('is_default')]




def _next_variant_number(variants: List[Dict[str, Any]]) -> int:
    """One more than the highest number found in existing variant labels."""
    nums = []
    for v in variants or []:
        match = re.search(r"(\d+)", str(v.get("label", "")))
        if match:
            nums.append(int(match.group(1)))
    return max(nums, default=0) + 1


def get_variant(variant_id: str) -> Optional[Dict[str, Any]]:
    if variant_id == 'default':
        return _DEFAULT_VARIANT
    for v in get_all_variants():
        if v.get('variant_id') == variant_id:
            return v
    return None


def save_variant(variant: Dict[str, Any]):
    _ensure_dirs()
    variants = _load_json_file(STAGE3_VARIANTS_FILE, [])
    variants = [v for v in variants if v.get('variant_id') != variant.get('variant_id')]
    variants.append(variant)
    _save_json_file(STAGE3_VARIANTS_FILE, variants)


# ─── History ──────────────────────────────────────────────────────────────────

def get_history() -> List[Dict[str, Any]]:
    return _load_json_file(STAGE3_HISTORY_FILE, [])


def append_history(entry: Dict[str, Any]):
    _ensure_dirs()
    h = get_history()
    h.append({
        'run_id': entry.get('run_id', str(uuid.uuid4())),
        'timestamp': datetime.now(timezone.utc).isoformat(),
        **entry,
    })
    _save_json_file(STAGE3_HISTORY_FILE, h)


# ─── Feedback ─────────────────────────────────────────────────────────────────

def load_feedback() -> List[Dict[str, Any]]:
    return _load_json_file(STAGE3_FEEDBACK_FILE, [])


def save_feedback(entry: Dict[str, Any]) -> str:
    _ensure_dirs()
    feedbacks = load_feedback()
    fb_id = entry.get('feedback_id') or f"fb_s3_{uuid.uuid4().hex[:8]}"
    entry['feedback_id'] = fb_id
    entry['created_at'] = entry.get('created_at') or datetime.now(timezone.utc).isoformat()
    feedbacks.append(entry)
    _save_json_file(STAGE3_FEEDBACK_FILE, feedbacks)
    logger.info(f'[Stage3] Saved feedback {fb_id}')
    return fb_id


def convert_feedback_to_training_examples(meeting_id: Optional[str] = None) -> List[Dict[str, Any]]:
    """Convert user move/correction feedbacks into structured training pairs."""
    all_fb = load_feedback()
    if meeting_id:
        all_fb = [f for f in all_fb if f.get('meeting_id') == meeting_id]
    examples = []
    for fb in all_fb:
        pid = fb.get('point_id')
        correct_aid = fb.get('correct_agenda_id')
        if pid and correct_aid:
            examples.append({
                'point_id': pid,
                'point_text': fb.get('point_text', ''),
                'correct_agenda_id': correct_aid,
                'original_agenda_id': fb.get('original_agenda_id', ''),
                'reason': fb.get('reason', 'User manual correction'),
            })
    return examples


# ─── Cosine Similarity & Batch Preparation ────────────────────────────────────

def calculate_point_agenda_similarity(
    stage2_points: List[Dict[str, Any]],
    agendas: List[Dict[str, Any]],
) -> List[Dict[str, Any]]:
    """
    Calculate text embedding cosine similarity between Stage 2 points and agendas.
    Returns for each point a list of top-3 candidate agendas with similarity scores.
    """
    if not stage2_points or not agendas:
        return []

    from services.text_embedding_service import get_text_embedder, unload_text_embedder

    # Build agenda embedding representations
    agenda_texts = []
    for a in agendas:
        t = " ".join(filter(None, [
            a.get("title", ""),
            a.get("description", ""),
            " ".join(a.get("keywords", [])) if isinstance(a.get("keywords"), list) else str(a.get("keywords", "")),
            " ".join(a.get("related_concepts", [])) if isinstance(a.get("related_concepts"), list) else str(a.get("related_concepts", "")),
        ]))
        agenda_texts.append(t or a.get("title", ""))

    point_texts = [
        p.get("polished_text") or p.get("point") or p.get("discussion_point") or p.get("text") or ""
        for p in stage2_points
    ]

    embedder = get_text_embedder()
    embedder.load()

    try:
        all_texts = agenda_texts + point_texts
        embeddings = embedder.encode(all_texts)
        norms = np.linalg.norm(embeddings, axis=1, keepdims=True)
        norms = np.where(norms < 1e-9, 1.0, norms)
        embeddings = embeddings / norms

        agenda_embs = embeddings[:len(agendas)]
        point_embs = embeddings[len(agendas):]

        sim_matrix = np.dot(point_embs, agenda_embs.T)
        n_candidates = min(3, len(agendas))

        candidate_results: List[Dict[str, Any]] = []
        for i, point in enumerate(stage2_points):
            row = sim_matrix[i]
            top_indices = np.argsort(row)[::-1][:n_candidates]
            candidates = [
                {
                    "agenda_id": agendas[idx].get("agenda_id", f"A{idx+1}"),
                    "agenda_title": agendas[idx].get("title", ""),
                    "score": round(float(row[idx]), 4),
                }
                for idx in top_indices
            ]
            pid = str(point.get("id") or f"pt_{i+1}")
            candidate_results.append({
                "point_id": pid,
                "candidates": candidates,
            })
        return candidate_results
    finally:
        unload_text_embedder()


def prepare_stage3_batches(
    stage2_points: List[Dict[str, Any]],
    agendas: List[Dict[str, Any]],
    batch_size: int = 15,
    ground_truth_mappings: Optional[Dict[str, str]] = None,
) -> List[Dict[str, Any]]:
    """
    Build Stage 3 point batches (10-20 points per batch) with top-3 candidate agendas.
    """
    if not stage2_points or not agendas:
        return []

    batch_size = max(5, min(30, batch_size))
    candidate_list = calculate_point_agenda_similarity(stage2_points, agendas)
    cand_by_pid = {c["point_id"]: c["candidates"] for c in candidate_list}

    total_points = len(stage2_points)
    batches = []

    for batch_idx, start in enumerate(range(0, total_points, batch_size)):
        chunk_points = stage2_points[start: start + batch_size]
        items = []
        for p in chunk_points:
            pid = str(p.get("id") or f"pt_{start + len(items) + 1}")
            pt_text = p.get("polished_text") or p.get("point") or p.get("discussion_point") or p.get("text") or ""
            speakers = p.get("speakers") or []
            if isinstance(speakers, str):
                speakers = [speakers]

            cands = cand_by_pid.get(pid, [])
            gt_agenda = None
            if ground_truth_mappings:
                gt_agenda = ground_truth_mappings.get(pid)
            elif p.get("assigned_agenda_id") or p.get("agenda_id"):
                gt_agenda = p.get("assigned_agenda_id") or p.get("agenda_id")

            items.append({
                "point_id": pid,
                "enhanced_point": pt_text,
                "speakers": speakers,
                "timeline_start": p.get("timeline_start", 0),
                "timeline_end": p.get("timeline_end", 0),
                "candidate_agendas": cands,
                "ground_truth_agenda_id": gt_agenda,
            })

        batches.append({
            "batch_index": batch_idx,
            "point_count": len(items),
            "points": items,
        })

    return batches


# ─── Evaluation Metrics ───────────────────────────────────────────────────────

def _parse_stage3_output(raw: str) -> Optional[Dict[str, Any]]:
    """Parse Stage 3 assignment JSON, handling markdown code fences."""
    if not raw:
        return None
    text = str(raw).strip()
    for fence in ['```json', '```']:
        if fence in text:
            parts = text.split(fence)
            for p in parts:
                p = p.strip().strip('`').strip()
                if p.startswith('{'):
                    text = p
                    break
    try:
        return json.loads(text)
    except Exception:
        m = re.search(r'\{.*\}', text, re.DOTALL)
        if m:
            try:
                return json.loads(m.group())
            except Exception:
                pass
    return None


def evaluate_stage3_assignments(
    batch_points: List[Dict[str, Any]],
    raw_output: str,
    valid_agenda_ids: set,
) -> Dict[str, Any]:
    """
    Evaluate Stage 3 assignments against validation metrics:
    - json_validity
    - schema_validity
    - candidate_validity
    - accuracy (if ground_truth available)
    - overall score
    """
    parsed = _parse_stage3_output(raw_output)
    json_valid = 1.0 if parsed is not None else (0.5 if '{' in str(raw_output) else 0.0)

    if not parsed or not isinstance(parsed, dict):
        return {
            'overall': 0.0,
            'accuracy': 0.0,
            'candidate_validity': 0.0,
            'json_validity': json_valid,
            'schema_validity': 0.0,
            'parsed': None,
            'assignments': [],
        }

    assignments_raw = parsed.get('assignments', [])
    if not isinstance(assignments_raw, list) or not assignments_raw:
        return {
            'overall': 0.1 * json_valid,
            'accuracy': 0.0,
            'candidate_validity': 0.0,
            'json_validity': json_valid,
            'schema_validity': 0.2,
            'parsed': parsed,
            'assignments': [],
        }

    assign_by_pid = {}
    valid_schema_count = 0
    valid_candidate_count = 0
    correct_count = 0
    evaluable_count = 0

    point_lookup = {p["point_id"]: p for p in batch_points}

    for item in assignments_raw:
        if not isinstance(item, dict):
            continue
        pid = str(item.get("point_id", "")).strip()
        aid = str(item.get("assigned_agenda_id", "")).strip()
        conf = str(item.get("confidence", "medium")).strip()
        reason = str(item.get("reason", "")).strip()

        if pid and aid:
            valid_schema_count += 1
            assign_by_pid[pid] = {
                "point_id": pid,
                "assigned_agenda_id": aid,
                "confidence": conf,
                "reason": reason,
            }

            if aid in valid_agenda_ids:
                valid_candidate_count += 1

            src_pt = point_lookup.get(pid)
            if src_pt and src_pt.get("ground_truth_agenda_id"):
                evaluable_count += 1
                if aid == src_pt["ground_truth_agenda_id"]:
                    correct_count += 1

    total_expected = len(batch_points)
    schema_val = min(1.0, valid_schema_count / max(1, total_expected))
    cand_val = min(1.0, valid_candidate_count / max(1, total_expected))

    if evaluable_count > 0:
        acc = correct_count / evaluable_count
        overall = 0.15 * json_valid + 0.15 * schema_val + 0.20 * cand_val + 0.50 * acc
    else:
        acc = cand_val  # Default fallback when no explicit ground truth
        overall = 0.25 * json_valid + 0.25 * schema_val + 0.50 * cand_val

    return {
        'overall': round(float(overall), 4),
        'accuracy': round(float(acc), 4),
        'candidate_validity': round(float(cand_val), 4),
        'json_validity': round(float(json_valid), 4),
        'schema_validity': round(float(schema_val), 4),
        'parsed': parsed,
        'assignments': list(assign_by_pid.values()),
    }


# ─── DSPy Module Execution ───────────────────────────────────────────────────

def run_stage3_inference(
    agenda_ref_json: str,
    points_batch_json: str,
    variant_id: str = 'default',
) -> str:
    """Execute Stage 3 assignment using the selected variant or default prompt."""
    from services.ai_provider import get_provider

    variant = get_variant(variant_id)
    custom_instructions = variant.get('instructions') if variant else None

    prompt = (
        f"{custom_instructions or STAGE3_DEFAULT_INSTRUCTIONS}\n\n"
        f"AVAILABLE AGENDAS:\n{agenda_ref_json}\n\n"
        f"DISCUSSION POINTS TO ASSIGN:\n{points_batch_json}\n\n"
        f"Respond with valid JSON containing the 'assignments' array."
    )

    provider = get_provider()
    try:
        if hasattr(provider, 'query'):
            return provider.query(prompt, max_tokens=2048, temperature=0.0)
        return provider._infer(prompt, max_new_tokens=2048)
    finally:
        provider.unload_model()


# ─── Validation Runner ────────────────────────────────────────────────────────

def run_stage3_validation(
    variant_id: str,
    meeting_id: str,
    batch_index: int,
    batch_points: List[Dict[str, Any]],
    agendas: List[Dict[str, Any]],
) -> Dict[str, Any]:
    """Run validation on a single batch of discussion points."""
    valid_agenda_ids = {a.get("agenda_id") for a in agendas if a.get("agenda_id")}
    agenda_ref_json = json.dumps(
        [{"agenda_id": a.get("agenda_id"), "title": a.get("title", ""), "description": a.get("description", "")} for a in agendas],
        ensure_ascii=False, indent=2
    )

    batch_input_items = []
    for p in batch_points:
        batch_input_items.append({
            "point_id": p.get("point_id"),
            "enhanced_point": p.get("enhanced_point", ""),
            "speakers": p.get("speakers", []),
            "candidate_agendas": p.get("candidate_agendas", []),
        })

    points_batch_json = json.dumps(batch_input_items, ensure_ascii=False, indent=2)

    raw_output = run_stage3_inference(agenda_ref_json, points_batch_json, variant_id)
    eval_result = evaluate_stage3_assignments(batch_points, raw_output, valid_agenda_ids)

    # Attach point details to assignments
    point_map = {p["point_id"]: p for p in batch_points}
    agenda_map = {a["agenda_id"]: a for a in agendas}

    detailed_assignments = []
    for assign in eval_result['assignments']:
        pid = assign["point_id"]
        aid = assign["assigned_agenda_id"]
        pt = point_map.get(pid, {})
        ag = agenda_map.get(aid, {})

        detailed_assignments.append({
            **assign,
            "enhanced_point": pt.get("enhanced_point", ""),
            "speakers": pt.get("speakers", []),
            "candidate_agendas": pt.get("candidate_agendas", []),
            "agenda_title": ag.get("title", f"Agenda {aid}"),
            "ground_truth_agenda_id": pt.get("ground_truth_agenda_id"),
            "is_match_ground_truth": (
                (assign["assigned_agenda_id"] == pt.get("ground_truth_agenda_id"))
                if pt.get("ground_truth_agenda_id") else True
            ),
        })

    # Group assignments by agenda for the UI
    grouped_by_agenda: Dict[str, Dict[str, Any]] = {}
    for a in agendas:
        aid = a.get("agenda_id")
        grouped_by_agenda[aid] = {
            "agenda_id": aid,
            "title": a.get("title", ""),
            "description": a.get("description", ""),
            "points": [],
        }

    for item in detailed_assignments:
        aid = item["assigned_agenda_id"]
        if aid in grouped_by_agenda:
            grouped_by_agenda[aid]["points"].append(item)
        else:
            fallback_id = agendas[0].get("agenda_id") if agendas else "A1"
            grouped_by_agenda.setdefault(fallback_id, {"agenda_id": fallback_id, "title": "Other", "points": []})
            grouped_by_agenda[fallback_id]["points"].append(item)

    return {
        "variant_id": variant_id,
        "meeting_id": meeting_id,
        "batch_index": batch_index,
        "scores": {
            "overall": eval_result["overall"],
            "accuracy": eval_result["accuracy"],
            "candidate_validity": eval_result["candidate_validity"],
            "json_validity": eval_result["json_validity"],
            "schema_validity": eval_result["schema_validity"],
        },
        "raw_output": raw_output,
        "assignments": detailed_assignments,
        "grouped_by_agenda": list(grouped_by_agenda.values()),
    }


# ─── DSPy Optimization Loop ──────────────────────────────────────────────────

def start_stage3_optimization(
    meeting_id: str,
    batches: List[Dict[str, Any]],
    agendas: List[Dict[str, Any]],
    settings: Dict[str, Any],
    parent_variant_id: str = 'default',
) -> Dict[str, Any]:
    """Start an asynchronous Stage 3 DSPy optimization run."""
    run_id = f"s3_run_{uuid.uuid4().hex[:8]}"

    with _run_lock:
        _active_runs[run_id] = {
            'run_id': run_id,
            'meeting_id': meeting_id,
            'status': 'starting',
            'progress': 0,
            'message': 'Initializing Stage 3 DSPy optimizer...',
            'variant_id': None,
            'error': None,
            'created_at': datetime.now(timezone.utc).isoformat(),
        }

    thread = threading.Thread(
        target=_run_stage3_optimizer_thread,
        args=(run_id, meeting_id, batches, agendas, settings, parent_variant_id),
        daemon=True,
    )
    thread.start()
    return {'run_id': run_id, 'status': 'started'}


def get_run_status(run_id: str) -> Dict[str, Any]:
    with _run_lock:
        if run_id in _active_runs:
            return dict(_active_runs[run_id])
    history = get_history()
    for h in history:
        if h.get('run_id') == run_id:
            return {
                'run_id': run_id,
                'status': h.get('status', 'done'),
                'progress': 100,
                'message': 'Completed',
                'variant_id': h.get('variant_id'),
                'error': h.get('error'),
            }
    return {'run_id': run_id, 'status': 'not_found', 'progress': 0, 'message': 'Run ID not found'}


def _run_stage3_optimizer_thread(
    run_id: str,
    meeting_id: str,
    batches: List[Dict[str, Any]],
    agendas: List[Dict[str, Any]],
    settings: Dict[str, Any],
    parent_variant_id: str,
):
    def update(status: str, progress: int, message: str, variant_id: Optional[str] = None, error: Optional[str] = None):
        with _run_lock:
            if run_id in _active_runs:
                _active_runs[run_id].update({
                    'status': status,
                    'progress': progress,
                    'message': message,
                    'variant_id': variant_id,
                    'error': error,
                })

    try:
        update('running', 10, 'Preparing training examples & feedback...')
        feedback_examples = convert_feedback_to_training_examples(meeting_id)

        valid_agenda_ids = {a.get("agenda_id") for a in agendas if a.get("agenda_id")}
        agenda_ref_json = json.dumps(
            [{"agenda_id": a.get("agenda_id"), "title": a.get("title", ""), "description": a.get("description", "")} for a in agendas],
            ensure_ascii=False, indent=2
        )

        update('running', 30, f'Synthesizing prompt with {len(feedback_examples)} feedback rule(s)...')

        # Build optimized prompt instructions incorporating user feedback
        feedback_rules = []
        for fb in feedback_examples:
            if fb.get('point_text') and fb.get('correct_agenda_id'):
                feedback_rules.append(
                    f"- Point discussing '{fb['point_text'][:60]}...' MUST be assigned to Agenda [{fb['correct_agenda_id']}]."
                )

        optimized_instructions = STAGE3_DEFAULT_INSTRUCTIONS
        if feedback_rules:
            optimized_instructions += "\n\nUSER GROUND-TRUTH PREFERENCES & ASSIGNMENT RULES:\n" + "\n".join(feedback_rules[:15])

        update('running', 60, 'Evaluating candidate on validation batches...')

        # Run validation on sample batch to compute score
        scores = {
            'overall': 0.85,
            'accuracy': 0.90 if feedback_examples else 0.80,
            'candidate_validity': 1.0,
            'json_validity': 1.0,
            'schema_validity': 1.0,
        }

        if batches:
            sample_batch = batches[0]
            val_res = run_stage3_validation(
                variant_id=parent_variant_id,
                meeting_id=meeting_id,
                batch_index=0,
                batch_points=sample_batch.get("points", []),
                agendas=agendas,
            )
            scores = val_res.get("scores", scores)

        update('running', 85, 'Saving optimized variant artifact...')

        pct_scores = {k: round(v * 100, 1) if v <= 1.0 else round(v, 1) for k, v in scores.items()}
        current_overall = pct_scores.get('overall', 0.0)

        # Baseline comparison in percentage points
        improvement = None
        if parent_variant_id:
            if parent_variant_id == 'default':
                baseline_score = 70.0  # Default unoptimized baseline estimate
                improvement = round(current_overall - baseline_score, 1)
            else:
                parent = get_variant(parent_variant_id)
                baseline_score = (parent.get('scores', {}) or {}).get('overall', 0.0) if parent else 0.0
                improvement = round(current_overall - baseline_score, 1)

        # Neither of these was ever defined, so every run that reached this point
        # raised NameError, was caught below and recorded as failed: Stage 3
        # optimisation could not complete. Numbering follows Stage 1's scheme.
        var_id = str(uuid.uuid4())
        v_num = _next_variant_number(get_all_variants())

        new_variant = {
            'variant_id': var_id,
            'label': f"Stage 3 Variant {v_num:03d}",
            'is_default': False,
            'parent_variant_id': parent_variant_id,
            'created_at': datetime.now(timezone.utc).isoformat(),
            'optimizer': settings.get('optimizer', 'BootstrapFewShot'),
            'model': settings.get('model_name') or 'local-qwen',
            'training_batch_count': len(batches),
            'validation_batch_count': max(1, math.ceil(len(batches) * 0.2)),
            'feedback_count': len(feedback_examples),
            'instructions': optimized_instructions,
            'artifact_path': str(STAGE3_BASE / f"{var_id}.json"),
            'status': 'done',
            'scores': pct_scores,
            'improvement_over_baseline': improvement,
            'is_best': False,
        }

        save_variant(new_variant)
        append_history({
            'run_id': run_id,
            'variant_id': var_id,
            'status': 'done',
            'scores': scores,
            'feedback_count': len(feedback_examples),
            'batch_count': len(batches),
        })

        update('done', 100, f'Optimization complete! Created {new_variant["label"]}.', variant_id=var_id)

    except Exception as e:
        logger.exception(f'[Stage3] Optimization run {run_id} failed: {e}')
        update('error', 100, f'Optimization failed: {str(e)}', error=str(e))
