# -*- coding: utf-8 -*-
"""
Safety Filter — YouTube Policy Shield for ViralCutter
======================================================

Scans the transcript text of every AI-selected viral segment and blocks (or
flags) segments whose content is likely to violate the YouTube "Hate speech"
policy (الكلام الذي يحضّ على الكراهية) and related policies (harassment,
violent threats), **before** the clips are cut and uploaded.

Why this exists
---------------
YouTube issues strikes per uploaded clip. A single clip containing a slur or
a call to violence can get a channel a strike even when the source video was
fine. ViralCutter now filters those segments out of the cutting list.

Design
------
* 100% local and offline — no API calls, no extra dependencies.
* Multilingual blocklist: Arabic (فصحى + لهجات: مغاربية/جزائرية، خليجية،
  شامية، مصرية), English, Portuguese, French, Spanish, Turkish.
* Robust normalization so common evasions still match:
    - Arabic diacritics / tatweel removal (حَرَام → حرم، حـــرم → حرم)
    - Alef/Hamza/Ya/Taa-marbuta folding (أإآ→ا، ى→ي، ة→ه)
    - Latin accent folding (unicodedata NFKD)
    - Leetspeak / symbol substitution (@→a, 3→ع, $→s, ...)
    - Collapsed repeated letters (كراااهية → كراهية)
* Three severity levels:
    - ``high``   : slurs / dehumanization / calls to violence  → always blocked
    - ``medium`` : strong profanity / harassment               → blocked in ``block`` mode
    - ``low``    : borderline words                            → only reported
* Modes:
    - ``block`` : remove offending segments from the cutting list (default)
    - ``flag``  : keep the segments but annotate them (``safety`` field) and
                  write the report — nothing is removed
    - ``off``   : do nothing
* Users can extend/override the term list with a ``safety_terms.json`` file
  placed in the repo root or in the project folder. See
  ``safety_terms.example.json``.

Outputs (written to the project folder)
---------------------------------------
* ``safety_report.json`` — full report: per-segment verdicts, matched terms,
  categories, severities and approximate timestamps.
"""

import json
import os
import re
import unicodedata
from datetime import datetime

# ---------------------------------------------------------------------------
# Blocklist
# ---------------------------------------------------------------------------
# Each entry: (phrase, language, severity, category)
#   category: hate_slur | hate_dehumanize | violence_threat | harassment | profanity
#
# NOTE: these lists intentionally target *strong* policy-violating terms.
# They are not meant to censor normal speech — mild words are "low" severity
# and never block a segment by themselves.

BLOCKLIST = [
    # ------------------------------------------------------------------ AR
    # Slurs / dehumanization targeting groups (الكراهية ضد فئات)
    ("روث البشر", "ar", "high", "hate_dehumanize"),
    ("حثالة البشر", "ar", "high", "hate_dehumanize"),
    ("حثالة المجتمع", "ar", "high", "hate_dehumanize"),
    ("ابن الكلب", "ar", "high", "hate_slur"),
    ("يا كلب", "ar", "medium", "harassment"),
    ("يا حيوان", "ar", "medium", "harassment"),
    ("يا بهيم", "ar", "medium", "harassment"),
    ("كفار", "ar", "low", "hate_slur"),
    ("كفرة", "ar", "low", "hate_slur"),
    ("ملاحدة", "ar", "medium", "hate_slur"),
    ("روافض", "ar", "high", "hate_slur"),
    ("رافضي", "ar", "high", "hate_slur"),
    ("نواصب", "ar", "high", "hate_slur"),
    ("صهيوني قذر", "ar", "high", "hate_slur"),
    ("يهودي قذر", "ar", "high", "hate_slur"),
    ("نصارى قذرون", "ar", "high", "hate_slur"),
    ("عبيد", "ar", "low", "hate_slur"),
    ("زنجي", "ar", "high", "hate_slur"),
    ("عرق حقير", "ar", "high", "hate_dehumanize"),
    ("جنس حقير", "ar", "high", "hate_dehumanize"),
    ("اقذر خلق", "ar", "high", "hate_dehumanize"),
    ("قذرين", "ar", "low", "profanity"),
    ("نجس", "ar", "medium", "hate_dehumanize"),
    ("نجسه", "ar", "medium", "hate_dehumanize"),
    ("داعر", "ar", "high", "profanity"),
    ("عاهر", "ar", "high", "profanity"),
    ("عاهرة", "ar", "high", "profanity"),
    ("شرموط", "ar", "high", "profanity"),
    ("شرموطة", "ar", "high", "profanity"),
    ("زانية", "ar", "high", "profanity"),
    ("زاني", "ar", "high", "profanity"),
    ("قحبة", "ar", "high", "profanity"),
    ("منيوك", "ar", "high", "profanity"),
    ("نيك", "ar", "high", "profanity"),
    ("زبي", "ar", "high", "profanity"),
    ("قحاب", "ar", "high", "profanity"),
    ("زامل", "ar", "high", "hate_slur"),
    ("بوسبير", "ar", "high", "hate_slur"),
    ("خنزير", "ar", "medium", "harassment"),
    ("خنازير", "ar", "high", "hate_dehumanize"),
    ("قردة", "ar", "high", "hate_dehumanize"),
    ("يا كلاب", "ar", "medium", "harassment"),
    ("ابن الزنا", "ar", "high", "profanity"),
    ("ابن الحرام", "ar", "high", "profanity"),
    ("ولد الحرام", "ar", "high", "profanity"),
    ("ولد القحبة", "ar", "high", "profanity"),
    ("يا عرص", "ar", "high", "profanity"),
    ("عرص", "ar", "high", "profanity"),
    ("متخلف عقليا", "ar", "high", "hate_slur"),
    ("منغولي", "ar", "high", "hate_slur"),
    ("معاق ذهنيا", "ar", "high", "hate_slur"),

    # Calls to violence (التحريض على العنف)
    ("اذبحهم", "ar", "high", "violence_threat"),
    ("اذبحوهم", "ar", "high", "violence_threat"),
    ("اقتلوهم", "ar", "high", "violence_threat"),
    ("اقتلهم", "ar", "high", "violence_threat"),
    ("اقضي عليهم", "ar", "high", "violence_threat"),
    ("ابادهم", "ar", "high", "violence_threat"),
    ("إبادتهم", "ar", "high", "violence_threat"),
    ("حرقوهم", "ar", "high", "violence_threat"),
    ("يستحق الذبح", "ar", "high", "violence_threat"),
    ("يستحق القتل", "ar", "high", "violence_threat"),
    ("لازم نقتلهم", "ar", "high", "violence_threat"),
    ("يجب قتلهم", "ar", "high", "violence_threat"),
    ("موتوا", "ar", "high", "violence_threat"),
    ("الموت لهم", "ar", "high", "violence_threat"),
    ("سأقتلك", "ar", "high", "violence_threat"),
    ("راح نقتلك", "ar", "high", "violence_threat"),
    ("ندبحك", "ar", "high", "violence_threat"),

    # ------------------------------------------------------------------ EN
    ("nigger", "en", "high", "hate_slur"),
    ("nigga", "en", "high", "hate_slur"),
    ("faggot", "en", "high", "hate_slur"),
    ("fag", "en", "high", "hate_slur"),
    ("kike", "en", "high", "hate_slur"),
    ("chink", "en", "high", "hate_slur"),
    ("spic", "en", "high", "hate_slur"),
    ("wetback", "en", "high", "hate_slur"),
    ("raghead", "en", "high", "hate_slur"),
    ("towelhead", "en", "high", "hate_slur"),
    ("sand nigger", "en", "high", "hate_slur"),
    ("white trash", "en", "high", "hate_slur"),
    ("subhuman", "en", "high", "hate_dehumanize"),
    ("sub-human", "en", "high", "hate_dehumanize"),
    ("vermin", "en", "low", "hate_dehumanize"),
    ("cockroaches", "en", "low", "hate_dehumanize"),
    ("kill them all", "en", "high", "violence_threat"),
    ("kill all", "en", "high", "violence_threat"),
    ("exterminate", "en", "high", "violence_threat"),
    ("gas the", "en", "high", "violence_threat"),
    ("i will kill you", "en", "high", "violence_threat"),
    ("gonna kill you", "en", "high", "violence_threat"),
    ("death to", "en", "high", "violence_threat"),
    ("retard", "en", "high", "hate_slur"),
    ("retarded", "en", "high", "hate_slur"),
    ("tranny", "en", "high", "hate_slur"),
    ("whore", "en", "high", "profanity"),
    ("slut", "en", "high", "profanity"),
    ("cunt", "en", "high", "profanity"),
    ("motherfucker", "en", "high", "profanity"),
    ("son of a bitch", "en", "high", "profanity"),
    ("go to hell", "en", "low", "profanity"),

    # ------------------------------------------------------------------ PT
    ("macaco", "pt", "high", "hate_slur"),
    ("crioulo", "pt", "high", "hate_slur"),
    ("viado", "pt", "high", "hate_slur"),
    ("bicha", "pt", "high", "hate_slur"),
    ("traveco", "pt", "high", "hate_slur"),
    ("vadia", "pt", "high", "profanity"),
    ("puta", "pt", "high", "profanity"),
    ("vagabunda", "pt", "high", "profanity"),
    ("filho da puta", "pt", "high", "profanity"),
    ("retardado", "pt", "high", "hate_slur"),
    ("mata eles", "pt", "high", "violence_threat"),
    ("matar todos", "pt", "high", "violence_threat"),
    ("morte aos", "pt", "high", "violence_threat"),
    ("vou te matar", "pt", "high", "violence_threat"),

    # ------------------------------------------------------------------ FR
    ("nègre", "fr", "high", "hate_slur"),
    ("bougnoule", "fr", "high", "hate_slur"),
    ("pédé", "fr", "high", "hate_slur"),
    ("salope", "fr", "high", "profanity"),
    ("pute", "fr", "high", "profanity"),
    ("fils de pute", "fr", "high", "profanity"),
    ("attardé", "fr", "high", "hate_slur"),
    ("tuez-les", "fr", "high", "violence_threat"),
    ("mort aux", "fr", "high", "violence_threat"),
    ("je vais te tuer", "fr", "high", "violence_threat"),

    # ------------------------------------------------------------------ ES
    ("maricón", "es", "high", "hate_slur"),
    ("puta", "es", "high", "profanity"),
    ("hijo de puta", "es", "high", "profanity"),
    ("retrasado", "es", "high", "hate_slur"),
    ("mátalos", "es", "high", "violence_threat"),
    ("muerte a los", "es", "high", "violence_threat"),
    ("te voy a matar", "es", "high", "violence_threat"),

    # ------------------------------------------------------------------ TR
    ("orospu", "tr", "high", "profanity"),
    ("piç", "tr", "high", "profanity"),
    ("ibne", "tr", "high", "hate_slur"),
    ("öldüreceğim", "tr", "high", "violence_threat"),
    ("seni öldüreceğim", "tr", "high", "violence_threat"),
    ("geber", "tr", "high", "violence_threat"),
]

SEVERITY_ORDER = {"low": 1, "medium": 2, "high": 3}

# ---------------------------------------------------------------------------
# Normalization
# ---------------------------------------------------------------------------

_AR_DIACRITICS = re.compile(
    "[ً-ْٰـۖ-ۜ۟-۪ۨ-ۭ]"
)

_AR_MAP = str.maketrans({
    "أ": "ا", "إ": "ا", "آ": "ا", "ٱ": "ا",
    "ى": "ي", "ئ": "ي", "ؤ": "و",
    "ة": "ه",
})

_LEET_MAP = str.maketrans({
    "@": "a", "4": "a",
    "8": "b",
    "(": "c", "<": "c",
    "3": "ع",  # Arabizi
    "€": "e",
    "6": "g",
    "#": "h",
    "1": "i", "!": "i", "|": "i",
    "0": "o",
    "9": "q",
    "$": "s", "5": "s",
    "7": "ح",  # Arabizi
    "2": "ا",  # Arabizi hamza
    "+": "t",
    "µ": "u",
    "×": "x",
    "¥": "y",
})


def _fold_repeats(text):
    """Collapse 3+ repeated chars into one (كــراهية / craaaazy → كراهية / crazy)."""
    return re.sub(r"(.)\1{2,}", r"\1", text)


def normalize_text(text):
    """Normalize text so that blocklist matching is robust to evasion."""
    if not text:
        return ""
    t = unicodedata.normalize("NFKC", str(text))
    t = _AR_DIACRITICS.sub("", t)          # Arabic diacritics + tatweel
    t = t.translate(_AR_MAP)               # Alef/Ya/Taa-marbuta folding
    t = t.lower()
    # Latin accent folding
    t = unicodedata.normalize("NFKD", t)
    t = "".join(ch for ch in t if not unicodedata.combining(ch))
    t = t.translate(_LEET_MAP)
    t = _fold_repeats(t)
    # keep letters/digits/arabic range + spaces
    t = re.sub(r"[^\w\s]", " ", t, flags=re.UNICODE)
    # strip the Arabic definite article "ال" (and و/ف/ب/ك/ل + ال) attached to
    # words: القردة → قردة ، والخنازير → خنازير
    t = re.sub(r"(?<!\w)[وفبكل]?ال(?=\w{2,})", "", t)
    t = re.sub(r"\s+", " ", t).strip()
    return t


# Pre-normalize the blocklist once (phrase matching happens on token level)
def _build_index(extra_terms=None):
    index = []
    entries = list(BLOCKLIST)
    if extra_terms:
        for e in extra_terms:
            if isinstance(e, dict):
                entries.append((
                    e.get("term", ""), e.get("lang", "custom"),
                    e.get("severity", "high"), e.get("category", "custom"),
                ))
            elif isinstance(e, str):
                entries.append((e, "custom", "high", "custom"))
    for phrase, lang, severity, category in entries:
        norm = normalize_text(phrase)
        if not norm:
            continue
        index.append({
            "term": phrase,
            "norm": norm,
            "tokens": norm.split(" "),
            "lang": lang,
            "severity": severity,
            "category": category,
        })
    # longer phrases first so multi-word matches win
    index.sort(key=lambda e: len(e["tokens"]), reverse=True)
    return index


# ---------------------------------------------------------------------------
# Matching
# ---------------------------------------------------------------------------

def find_matches(text, index=None, min_severity="low", allow_terms=None):
    """Return all blocklist matches found in *text* (already raw text).

    ``allow_terms`` excludes specific blocklist terms (false-positive
    control) — matching is done on the normalized form.
    """
    if index is None:
        index = _build_index()
    allow_norms = {normalize_text(t) for t in (allow_terms or [])}
    norm = normalize_text(text)
    if not norm:
        return []
    tokens = norm.split(" ")
    joined = " " + " ".join(tokens) + " "
    matches = []
    min_rank = SEVERITY_ORDER.get(min_severity, 1)
    for entry in index:
        if SEVERITY_ORDER.get(entry["severity"], 3) < min_rank:
            continue
        if entry["norm"] in allow_norms:
            continue
        phrase = " " + entry["norm"] + " "
        if phrase in joined:
            # approximate position (token index) for reporting
            pos = joined.find(phrase)
            approx_word = joined[:pos].count(" ")
            matches.append({
                "term": entry["term"],
                "lang": entry["lang"],
                "severity": entry["severity"],
                "category": entry["category"],
                "word_index": max(0, approx_word - 1),
            })
    return matches


# ---------------------------------------------------------------------------
# Transcript helpers
# ---------------------------------------------------------------------------

def load_transcript(project_folder):
    """Parse input.tsv / input.srt from the project folder.

    Implemented locally (instead of importing create_viral_segments) to keep
    this module side-effect free — importing create_viral_segments re-wraps
    sys.stdout at import time, which breaks pytest capture and notebooks.
    """
    input_tsv = os.path.join(project_folder, 'input.tsv')
    input_srt = os.path.join(project_folder, 'input.srt')

    transcript_segments = []

    if os.path.exists(input_tsv):
        try:
            with open(input_tsv, 'r', encoding='utf-8') as f:
                lines = f.readlines()[1:]
            for line in lines:
                parts = line.strip().split('\t')
                if len(parts) >= 3:
                    transcript_segments.append({
                        'start': float(parts[0]) / 1000.0,
                        'end': float(parts[1]) / 1000.0,
                        'text': parts[2],
                    })
        except Exception as e:
            print(f"[safety] Error parsing TSV: {e}")

    if not transcript_segments and os.path.exists(input_srt):
        try:
            with open(input_srt, 'r', encoding='utf-8') as f:
                srt_content = f.read()
            pattern = re.compile(
                r'(\d+)\n(\d{2}:\d{2}:\d{2},\d{3}) --> (\d{2}:\d{2}:\d{2},\d{3})\n((?:(?!\n\n).)*)',
                re.DOTALL)

            def srt_time_to_seconds(t_str):
                h, m, s = t_str.replace(',', '.').split(':')
                return int(h) * 3600 + int(m) * 60 + float(s)

            for match in pattern.findall(srt_content):
                transcript_segments.append({
                    'start': srt_time_to_seconds(match[1]),
                    'end': srt_time_to_seconds(match[2]),
                    'text': match[3].replace('\n', ' '),
                })
        except Exception as e:
            print(f"[safety] Error parsing SRT: {e}")

    return transcript_segments


def segment_text(segment, transcript_segments):
    """Concatenate transcript text that genuinely overlaps the segment window."""
    start = float(segment.get("start_time", 0) or 0)
    end = float(segment.get("end_time", start) or start)
    parts = []
    for ts in transcript_segments:
        ts_start = ts.get("start", 0)
        ts_end = ts.get("end", ts_start)
        # strict overlap: only chunks truly inside [start, end]
        if ts_end <= start + 0.05:
            continue
        if ts_start >= end - 0.05:
            break
        parts.append(ts.get("text", ""))
    text = " ".join(parts).strip()
    # Fallback: some AI segments carry their own text
    if not text:
        text = " ".join([
            str(segment.get("start_text", "")),
            str(segment.get("end_text", "")),
            str(segment.get("title", "")),
            str(segment.get("caption", "")),
        ]).strip()
    return text


def _approx_match_times(segment, transcript_segments, matches):
    """Approximate timestamp of each match inside the segment (for the report)."""
    text = segment_text(segment, transcript_segments)
    norm_words = normalize_text(text).split(" ")
    if not norm_words:
        return matches
    seg_start = float(segment.get("start_time", 0) or 0)
    seg_end = float(segment.get("end_time", seg_start) or seg_start)
    duration = max(0.001, seg_end - seg_start)
    n = len(norm_words)
    for m in matches:
        frac = min(0.99, max(0.0, m.get("word_index", 0) / max(1, n)))
        m["approx_time"] = round(seg_start + frac * duration, 2)
        m.pop("word_index", None)
    return matches


# ---------------------------------------------------------------------------
# Custom terms
# ---------------------------------------------------------------------------

def load_custom_terms(project_folder=None, extra_path=None):
    """Load user-provided terms from safety_terms.json (repo root, project
    folder, or an explicit path). Never raises.

    Returns ``{"extra_terms": [...], "allow_terms": [...]}``:
      * ``extra_terms`` — additional terms to BLOCK
      * ``allow_terms`` — terms to EXCLUDE from the built-in blocklist
        (false-positive control, e.g. a history channel saying "منغولي")
    """
    candidates = []
    if extra_path:
        candidates.append(extra_path)
    base_dir = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
    candidates.append(os.path.join(base_dir, "safety_terms.json"))
    if project_folder:
        candidates.append(os.path.join(project_folder, "safety_terms.json"))

    result = {"extra_terms": [], "allow_terms": []}
    for path in candidates:
        if not path or not os.path.exists(path):
            continue
        try:
            with open(path, "r", encoding="utf-8") as f:
                data = json.load(f)
            if isinstance(data, list):
                result["extra_terms"].extend(data)
            elif isinstance(data, dict):
                result["extra_terms"].extend(data.get("extra_terms", []))
                result["allow_terms"].extend(data.get("allow_terms", []))
        except Exception as e:
            print(f"[safety] Could not read custom terms from {path}: {e}")
    return result


# ---------------------------------------------------------------------------
# Main API
# ---------------------------------------------------------------------------

def analyze_segments(segments, transcript_segments=None, project_folder=None,
                     mode="block", min_severity="medium",
                     extra_terms_path=None):
    """
    Analyze a list of viral segments.

    Returns ``(result_segments, report)``:
      * ``block``  mode → result_segments excludes blocked segments
      * ``flag``   mode → result_segments is the full list, each segment gets a
                          ``safety`` annotation field
      * ``censor`` mode → like ``flag`` (keeps everything, annotated) — the
                          actual muting happens after cutting via
                          scripts/censor_engine.py
      * ``off``    mode → returns input untouched (still produces a report if
                          called directly)
    """
    segments = list(segments or [])
    if transcript_segments is None and project_folder:
        try:
            transcript_segments = load_transcript(project_folder)
        except Exception:
            transcript_segments = []
    transcript_segments = transcript_segments or []

    custom = load_custom_terms(project_folder, extra_terms_path)
    index = _build_index(custom.get("extra_terms", []))
    allow_terms = custom.get("allow_terms", [])
    block_threshold = SEVERITY_ORDER.get(min_severity, 2)

    report_entries = []
    kept = []
    blocked_count = 0

    for seg in segments:
        text = segment_text(seg, transcript_segments)
        matches = find_matches(text, index=index, min_severity="low",
                               allow_terms=allow_terms)
        blocking = [m for m in matches
                    if SEVERITY_ORDER.get(m["severity"], 3) >= block_threshold]

        entry = {
            "title": seg.get("title", ""),
            "start_time": seg.get("start_time"),
            "end_time": seg.get("end_time"),
            "status": "safe",
            "matches": _approx_match_times(seg, transcript_segments, matches),
        }

        if blocking and mode == "block":
            entry["status"] = "blocked"
            blocked_count += 1
        elif blocking and mode in ("flag", "censor"):
            entry["status"] = "flagged" if mode == "flag" else "censor"
            seg = dict(seg)
            seg["safety"] = {
                "flagged": True,
                "action": mode,
                "reasons": sorted({m["category"] for m in blocking}),
                "terms": sorted({m["term"] for m in blocking}),
            }
            kept.append(seg)
        else:
            kept.append(seg)

        report_entries.append(entry)

    report = {
        "generated_at": datetime.now().isoformat(timespec="seconds"),
        "mode": mode,
        "min_severity": min_severity,
        "total_segments": len(segments),
        "kept": len(kept),
        "blocked": blocked_count,
        "flagged": sum(1 for e in report_entries if e["status"] == "flagged"),
        "censored": sum(1 for e in report_entries if e["status"] == "censor"),
        "segments": report_entries,
    }
    return kept, report


def apply_safety_filter(viral_segments, project_folder, mode="block",
                        min_severity="medium", extra_terms_path=None,
                        i18n=lambda k: k):
    """
    High-level helper used by main_improved.py:
      * filters the ``segments`` list inside the viral_segments dict
      * writes ``safety_report.json`` into the project folder
      * prints a human summary
    Returns the (possibly filtered) viral_segments dict.
    """
    if mode == "off" or not viral_segments or "segments" not in viral_segments:
        return viral_segments

    segments = viral_segments.get("segments", [])
    if not segments:
        return viral_segments

    kept, report = analyze_segments(
        segments,
        project_folder=project_folder,
        mode=mode,
        min_severity=min_severity,
        extra_terms_path=extra_terms_path,
    )

    # Persist report
    try:
        report_path = os.path.join(project_folder, "safety_report.json")
        with open(report_path, "w", encoding="utf-8") as f:
            json.dump(report, f, ensure_ascii=False, indent=2)
        print(i18n("[safety] Report saved to {}").format(report_path))
    except Exception as e:
        print(f"[safety] Could not save report: {e}")

    if mode == "block" and report["blocked"]:
        print(i18n("[safety] {} segment(s) BLOCKED for policy-violating content (hate speech / violence).").format(report["blocked"]))
        for entry in report["segments"]:
            if entry["status"] == "blocked":
                terms = ", ".join(sorted({m["term"] for m in entry["matches"]}))
                print(i18n("[safety]   ✗ '{}' ({}): {}").format(
                    entry["title"], entry["status"], terms))
    elif mode == "flag" and report["flagged"]:
        print(i18n("[safety] {} segment(s) flagged for review (kept).").format(report["flagged"]))
    elif mode == "censor":
        if report["censored"]:
            print(i18n("[safety] {} segment(s) contain policy-violating words — they will be BLEEPED (muted) after cutting.").format(report["censored"]))
        else:
            print(i18n("[safety] All {} segments passed the policy check ✔").format(report["total_segments"]))
    else:
        print(i18n("[safety] All {} segments passed the policy check ✔").format(report["total_segments"]))

    result = dict(viral_segments)
    result["segments"] = kept
    return result


# ---------------------------------------------------------------------------
# CLI
# ---------------------------------------------------------------------------

def main():
    import argparse

    parser = argparse.ArgumentParser(
        description="Filter viral segments that may violate YouTube hate-speech policy.")
    parser.add_argument("--project", required=True, help="Project folder containing viral_segments.txt")
    parser.add_argument("--mode", choices=["block", "flag", "off"], default="block")
    parser.add_argument("--min-severity", choices=["low", "medium", "high"], default="medium")
    parser.add_argument("--extra-terms", help="Path to safety_terms.json with extra terms")
    parser.add_argument("--in-place", action="store_true",
                        help="Rewrite viral_segments.txt with the filtered list")
    args = parser.parse_args()

    segments_path = os.path.join(args.project, "viral_segments.txt")
    if not os.path.exists(segments_path):
        print(f"[safety] {segments_path} not found.")
        raise SystemExit(1)

    with open(segments_path, "r", encoding="utf-8") as f:
        viral_segments = json.load(f)

    filtered = apply_safety_filter(
        viral_segments,
        project_folder=args.project,
        mode=args.mode,
        min_severity=args.min_severity,
        extra_terms_path=args.extra_terms,
    )

    if args.in_place and args.mode == "block":
        with open(segments_path, "w", encoding="utf-8") as f:
            json.dump(filtered, f, ensure_ascii=False, indent=4)
        print(f"[safety] {segments_path} updated in place.")


if __name__ == "__main__":
    main()
