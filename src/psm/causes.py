"""Parse Form 2010 fields 18 (probable) and 19 (contributing) cause statements.

Two jobs, deliberately separated:

* :func:`segment_statements` splits a field into individual cause statements.
* :func:`candidate_category` pulls the *category-like prefix* from a statement
  without consulting any vocabulary list.

The second is what makes vocabulary **induction** honest. If the parser only
recognised a hard-coded category list, the induced vocabulary would be that
list reflected back — the classic way to "discover" what you already assumed.
So induction runs vocabulary-blind, and the observed distribution decides
whether a closed vocabulary exists at all.

Delimiter forms observed in the corpus (all must parse):

    Equipment failure: Inadequate preventive maintenance- <desc>
    Human Performance Error- Inadequate knowledge of equipment operation: <desc>
    Communication: Inadequate job instructions provided. <desc>
    • Equipment Failure – Inadequate Equipment Inspection: <desc>
    Management Systems:                     <- bare header, bullets beneath
    • Inadequate job procedures. <desc>
    1) Equipment Failure – Inadequate preventative maintenance/...
    The BSEE incident investigation team determined ...   <- free prose, no typing
"""

from __future__ import annotations

import re
from dataclasses import asdict, dataclass

# Statement openers: bullet glyphs, or enumerators like "1)" / "2)." / "1.".
BULLET_RE = re.compile(r"^\s*(?:[••●▪·*]|[-–—](?=\s)|\d{1,2}\s*[).])\s*")

# Category/subcategory separators.
#
# An ASCII hyphen counts ONLY when followed by whitespace ("Human Performance
# Error- Inadequate knowledge..."). A hyphen with no space on either side is
# ordinary compounding, not a separator — an earlier `(?<=[a-z])-(?=[A-Z])`
# alternative split "Flexi-Coil hose" and invented a cause category "The Flexi".
# En/em dashes are separators regardless of spacing; they never compound here.
#
# The third alternative — a hyphen with whitespace on BOTH sides — was missing
# until 2026-08-29, and its absence was silent. The letter-lookbehind form
# requires the hyphen to touch the preceding word, so the equally common spaced
# form was not a separator at all:
#
#     Equipment Failure - Inadequate preventative maintenance- the crane's ...
#
# The parser ran past it to the next qualifying separator ("repair- the"),
# producing an 11-word head that MAX_CATEGORY_WORDS then rejected. Report
# BM 3 Cantium 5-Aug-2025 names four of the six canonical categories in its
# text and mapped to none of them. Measured effect of adding this alternative:
# mapped statements 460 -> 511 (+11%), typed 715 -> 766, and every one of the
# 51 newly-typed statements also maps — no new junk. "Flexi-Coil" is unaffected
# because it has no space after the hyphen.
SEP_CLASS = r"[:–—]|(?<=[a-zA-Z])-(?=\s)|(?<=\s)-(?=\s)"
SEP_RE = re.compile(SEP_CLASS)

# A category prefix is short and title-ish. Cap the length so a whole prose
# sentence ending in a dash cannot masquerade as a category.
MAX_CATEGORY_WORDS = 6
MAX_CATEGORY_CHARS = 60

CAUSE_STATUS = ("typed", "freetext", "absent_legitimate", "parse_failed")

# Field-label furniture that satisfies the category-prefix shape (short,
# title-ish, colon-separated) but is not a cause category. Confirmed leaking
# into field 18/19 body text via continuation-page markers and cross-field
# label bleed: report 030521-pdf (2003 EAC riser-insert failure, entirely
# free prose) matched "NOTE: ABB Vetco has redesigned..." and
# "LIST THE ADDITIONAL INFORMATION:" (field 20's own label) as typed
# categories. "LIST THE ..." is BSEE's own field-label phrasing (field 18 is
# literally "LIST THE PROBABLE CAUSE(S)"), so it generalises to any field's
# label bleeding into another field's body, not just field 20's.
FURNITURE_HEAD_RE = re.compile(r"^(?:NOTE|LIST\s+THE\b.*)$", re.IGNORECASE)

# `LIST THE ...` catches the label only while it is intact. In two-column soup
# BSEE's own field label wraps, and the tail lands on its own line carrying the
# colon:
#
#     19. LIST THE CONTRIBUTING CAUSE(S) OF
#     ACCIDENT:
#
# The first line is furniture and is rejected; the orphaned tail is short,
# title-ish and colon-separated, so it becomes a cause category called
# "ACCIDENT" — 24 statements corpus-wide, the third most common head in the
# corpus. tests/test_causes.py asserted only that the *unsplit* label is
# rejected, so the split form shipped untested.
#
# The tempting general rule — "an ALL-CAPS head is furniture" — is WRONG, and
# measurably so: of 11 all-caps heads in the corpus, 6 are the legitimate
# categories HUMAN ERROR, COMMUNICATION, SUPERVISION, EQUIPMENT FAILURE,
# MANAGEMENT SYSTEM and WORK ENVIRONMENT, covering 13 statements. So the
# fragments are listed as data in schema/bsee_form2010.yaml, and the all-caps
# test is retained only as a guard so a Title Case cause statement that happens
# to read "Property damaged: ..." is not swallowed.
_FURNITURE_FRAGMENTS: frozenset[str] | None = None


def _label_fragments() -> frozenset[str]:
    """Orphaned BSEE field-label tails, from the form spec. Cached."""
    global _FURNITURE_FRAGMENTS
    if _FURNITURE_FRAGMENTS is None:
        import yaml
        from pathlib import Path
        spec = Path(__file__).resolve().parents[2] / "schema" / "bsee_form2010.yaml"
        raw = yaml.safe_load(spec.read_text(encoding="utf-8"))
        _FURNITURE_FRAGMENTS = frozenset(
            normalise_category(f) for f in raw.get("cause_field_furniture", []))
    return _FURNITURE_FRAGMENTS


def is_label_fragment(head: str) -> bool:
    """True when ``head`` is an orphaned piece of a BSEE field label.

    Requires ALL CAPS: the leaked fragments always are, and real categories are
    written in Title Case far more often than not.
    """
    return head.isupper() and normalise_category(head) in _label_fragments()


@dataclass
class CauseStatement:
    raw: str
    category: str | None
    subcategory: str | None
    description: str | None
    delimiter_form: str


# A font with no ToUnicode mapping renders its bullet glyph as "(cid:129)".
# The surrounding text is perfectly readable -- these are not broken documents,
# and the document-level guard in psm.extract correctly leaves them `ok`. But an
# unmapped glyph carries no information, and left in place it becomes the head of
# a "category" called "(cid". Normalised to a real bullet so the existing bullet
# handling picks it up, rather than stripped, because that is what it is.
CID_GLYPH_RE = re.compile(r"\(cid:\d+\)\s*")


def strip_cid_glyphs(text: str) -> str:
    """Replace unmapped-glyph tokens with a bullet."""
    return CID_GLYPH_RE.sub("\u2022 ", text or "")


def unwrap(text: str) -> list[str]:
    """Join PDF hard-wraps into logical statements.

    A new statement begins at a bullet/enumerator, or at a line whose prefix
    before a separator looks like a category. Everything else continues the
    previous line.
    """
    lines = [ln.strip() for ln in strip_cid_glyphs(text).splitlines() if ln.strip()]
    out: list[str] = []
    for ln in lines:
        starts_new = bool(BULLET_RE.match(ln))
        if not starts_new and out:
            m = SEP_RE.search(ln)
            if m and m.start() <= MAX_CATEGORY_CHARS:
                head = ln[: m.start()].strip()
                # Require title-ish: begins uppercase, few words, no terminal
                # punctuation mid-head.
                if (
                    head
                    and head[0].isupper()
                    and len(head.split()) <= MAX_CATEGORY_WORDS
                    and not head.endswith((".", ","))
                ):
                    starts_new = True
        if starts_new or not out:
            out.append(ln)
        else:
            out[-1] += " " + ln
    return out


def segment_statements(text: str) -> list[str]:
    """Split a field-18/19 body into individual cause statements."""
    if not text or not text.strip():
        return []
    statements = unwrap(text)

    # A bare header ("Management Systems:") followed by bullets distributes its
    # category over those bullets.
    resolved: list[str] = []
    pending_header: str | None = None
    for st in statements:
        body = BULLET_RE.sub("", st).strip()
        is_bullet = bool(BULLET_RE.match(st))
        m = SEP_RE.search(body)
        is_bare_header = bool(m) and not body[m.end():].strip()
        if is_bare_header and not is_bullet:
            pending_header = body[: m.start()].strip()
            continue
        if pending_header and is_bullet:
            resolved.append(f"{pending_header}: {body}")
            continue
        pending_header = None
        resolved.append(body)
    if pending_header and not resolved:
        resolved.append(pending_header)
    return [s for s in resolved if s]


def candidate_category(statement: str) -> tuple[str | None, str]:
    """Return ``(category_prefix, delimiter_form)`` without using a vocabulary.

    ``category_prefix`` is ``None`` when the statement does not look typed at
    all — which is itself the finding for free-text-era reports.
    """
    body = BULLET_RE.sub("", strip_cid_glyphs(statement)).strip()
    if not body:
        return None, "empty"
    m = SEP_RE.search(body)
    if not m or m.start() > MAX_CATEGORY_CHARS:
        return None, "untyped_prose"
    head = body[: m.start()].strip(" .–—-")
    if not head or not head[0].isalpha() or len(head.split()) > MAX_CATEGORY_WORDS:
        return None, "untyped_prose"
    # Title-ish means it starts uppercase. `unwrap` has always required this to
    # begin a new statement; requiring it here too closes the gap where the
    # spaced-hyphen separator could pick a mid-sentence head out of prose
    # ("a well-known issue - the valve stuck - ..."). Measured cost: 2
    # statements corpus-wide, both junk ("construction", "of this incident
    # include").
    if not head[0].isupper():
        return None, "untyped_prose"
    if FURNITURE_HEAD_RE.match(head) or is_label_fragment(head):
        return None, "furniture"
    sep = body[m.start(): m.end()]
    form = {":": "colon"}.get(sep, "dash")
    return head, form


def parse_statement(statement: str) -> CauseStatement:
    """Best-effort split into category / subcategory / description."""
    body = BULLET_RE.sub("", strip_cid_glyphs(statement)).strip()
    category, form = candidate_category(body)
    if category is None:
        return CauseStatement(body, None, None, body or None, form)

    m = SEP_RE.search(body)
    rest = body[m.end():].strip()

    # Subcategory runs to the next separator or the first sentence end.
    m2 = SEP_RE.search(rest)
    dot = re.search(r"(?<=[a-z])\.(?=\s|$)", rest)
    cut = min([p.start() for p in (m2, dot) if p] or [len(rest)])
    # Bullet chars are in the strip set because a cid-glyph bullet can sit
    # mid-statement, after the category separator, where the leading-bullet
    # rule above has already run and cannot reach it.
    sub = rest[:cut].strip(" .–—-•●▪·*") or None
    desc = rest[cut:].strip(" .:–—-•●▪·*") or None
    if sub and len(sub.split()) > 14:  # a whole sentence, not a subcategory
        sub, desc = None, rest
    return CauseStatement(body, category, sub, desc, form)


def normalise_category(name: str) -> str:
    """Fold surface variation so ``Equipment Failure`` == ``Equipment failure``."""
    s = name.strip().lower()
    s = re.sub(r"[\s_]+", " ", s)
    s = re.sub(r"[^a-z0-9 /]", "", s)
    return s.strip()


def classify_field(text: str | None) -> str:
    """Assign a ``cause_status``. ``absent_legitimate`` is not a parse failure.

    Blank fields 18/19 are sometimes genuinely correct — e.g. a third-party
    vessel allision outside BSEE jurisdiction. Conflating that with a parse
    failure sends you chasing bugs that do not exist.
    """
    if text is None:
        return "parse_failed"
    stripped = text.strip()
    if not stripped or stripped.upper() in {"N/A", "NA", "NONE", "N/A.", "NONE."}:
        return "absent_legitimate"
    statements = segment_statements(stripped)
    if not statements:
        return "absent_legitimate"
    if any(candidate_category(s)[0] for s in statements):
        return "typed"
    return "freetext"


def parse_field(text: str | None) -> dict:
    """Full parse of one cause field, including its status."""
    status = classify_field(text)
    statements = segment_statements(text or "") if text else []
    return {
        "cause_status": status,
        "statements": [asdict(parse_statement(s)) for s in statements],
    }


# ---- leak-free text for the cause-classification task --------------------

# A parsed span is treated as a subcategory (and removed) when it is short,
# recurs, or has no description after it; a long one-off span followed by a
# description is the investigator's own sentence and is kept.
SUBCATEGORY_MAX_WORDS = 6
SUBCATEGORY_MIN_COUNT = 2
STEM_MAX_WORDS = 3
# 1-word stems are excluded: "the", "a", "not", "did" head 34 distinct subcategories
# and dropping them rewrote 231 of 524 labelled statements without moving the
# sentinel (8 hits either way). Set to 1 to include them.
STEM_MIN_WORDS = 2
_LEAD_STRIP = " \t\r\n:–—-"

_SUB_COUNTS: dict | None = None


def subcategory_counts(causes_csv) -> dict[str, int]:
    """Lower-cased parsed subcategory -> occurrences over every statement in
    ``causes_csv`` (labelled or not)."""
    import csv
    csv.field_size_limit(10 ** 9)
    counts: dict[str, int] = {}
    with open(causes_csv, encoding="utf-8", newline="") as fh:
        for row in csv.DictReader(fh):
            sub = parse_statement(row.get("Cause Description", "") or "").subcategory
            if sub:
                counts[sub.lower()] = counts.get(sub.lower(), 0) + 1
    return counts


def _default_sub_counts() -> dict[str, int]:
    global _SUB_COUNTS
    if _SUB_COUNTS is None:
        from pathlib import Path
        _SUB_COUNTS = subcategory_counts(
            Path(__file__).resolve().parents[2] / "data" / "processed" / "e19"
            / "real_only" / "causes.csv")
    return _SUB_COUNTS


def subcategory_stems(sub_counts: dict[str, int]) -> frozenset[str]:
    """Leading 2-3 word stems shared by two or more distinct parsed
    subcategories, computed from the data (BSEE subcategories are a family of
    templates: "inadequate communication between <x> and <y>")."""
    seen: dict[str, set[str]] = {}
    for sub in sub_counts:
        words = sub.split()
        for k in range(STEM_MIN_WORDS, min(STEM_MAX_WORDS, len(words)) + 1):
            seen.setdefault(" ".join(words[:k]), set()).add(sub)
    return frozenset(stem for stem, subs in seen.items() if len(subs) >= 2)


def strip_category(raw: str, sub_counts: dict[str, int] | None = None) -> str:
    """Cause text with the label-bearing opening removed.

    Removes (1) the category head, (2) the parsed subcategory -- always, even
    when ``parse_statement`` finds no description after it -- and (3) the
    leading ``[:–—-]`` characters and whitespace.

    A span counts as a subcategory if it occurs at least twice as a parsed
    subcategory in ``sub_counts`` (default: ``real_only/causes.csv``), has
    ``SUBCATEGORY_MAX_WORDS`` words or fewer, or has no description after it
    (the whole statement is head plus subcategory). A long once-seen span that
    IS followed by a description is the investigator's own sentence and is kept.

    The kept text is then scrubbed of any remaining leading label vocabulary,
    repeatedly: the row's own category head, a recurring subcategory phrase, or
    a 2-3 word stem shared by two or more distinct subcategories. Untyped prose
    is returned as is.

    ``sub_counts`` is the output of :func:`subcategory_counts`. Without it, the
    counts are lazily loaded from ``data/processed/e19/real_only/causes.csv`` on
    first use and memoized for the life of the process.
    """
    st = parse_statement(raw or "")
    if st.category is None:
        return st.raw.lstrip(_LEAD_STRIP).strip()
    counts = _default_sub_counts() if sub_counts is None else sub_counts
    sub = st.subcategory
    if sub and (len(sub.split()) <= SUBCATEGORY_MAX_WORDS
                or counts.get(sub.lower(), 0) >= SUBCATEGORY_MIN_COUNT
                or not st.description):
        text = st.description or ""
    else:
        m = SEP_RE.search(st.raw)
        text = st.raw[m.end():] if m else ""
    text = text.lstrip(_LEAD_STRIP).strip()
    phrases = sorted({s for s, n in counts.items() if n >= SUBCATEGORY_MIN_COUNT}
                     | {st.category.lower()}, key=lambda s: (-len(s), s))
    stems = subcategory_stems(counts)
    while True:
        low = text.lower()
        for s in phrases:
            if low.startswith(s) and (len(low) == len(s) or not low[len(s)].isalnum()):
                text = text[len(s):].lstrip(_LEAD_STRIP).strip()
                break
        else:
            words = low.split()
            for k in range(min(STEM_MAX_WORDS, len(words)), STEM_MIN_WORDS - 1, -1):
                if " ".join(words[:k]) in stems:
                    parts = text.split(None, k)
                    text = (parts[k] if len(parts) > k else "").lstrip(_LEAD_STRIP).strip()
                    break
            else:
                return text
