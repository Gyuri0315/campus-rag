"""Supabase RPC search wrapper."""

from __future__ import annotations

import hashlib
import logging
import re
import time
from typing import Any, Dict, List, Optional, Protocol

from supabase import Client, create_client

from .reranking import normalize_scores

logger = logging.getLogger(__name__)

ACADEMIC_KEYWORDS = (
    "학사",
    "수강",
    "졸업",
    "전공",
    "복수전공",
    "부전공",
    "전과",
    "성적",
    "학점",
    "장학",
    "휴학",
    "복학",
    "등록",
    "신청",
    "기간",
    "자격",
    "조건",
    "이수",
    "교직",
    "현장실습",
)

NOISE_PHRASES = (
    "개인정보 수집",
    "저작물 활용 동의서",
    "접수번호는 공란",
    "글자크기",
    "연구보고",
    "contents",
    "목 차",
)

GENERIC_STUB_TITLES = (
    "학부 소개",
    "학부소개",
    "졸업 후 진로",
    "졸업후진로",
    "교육과정",
    "국립 부경대학교 대학생활 E-하나로",
    "대학생활 E-하나로",
)

_REPEATED_CHAR_RE = re.compile(r"(.)\1{5,}")
_STANDALONE_JAMO_RE = re.compile(r"[ㄱ-ㅎㅏ-ㅣ]{6,}")

QUERY_TERM_GROUPS = {
    "복수전공": ("복수전공", "복수 전공", "다전공", "전공제도"),
    "부전공": ("부전공", "부 전공", "다전공", "전공제도"),
    "마이크로전공": ("마이크로전공", "마이크로 전공", "소단위전공", "소단위 전공"),
    "전과": ("전과", "전부", "전공변경"),
    "전공": ("전공", "전공제도"),
    "졸업": ("졸업", "졸업요건", "학위수여", "졸업작품", "졸업논문", "졸업사정"),
    "학점": ("학점", "소요학점", "이수학점"),
    "수강신청": ("수강신청", "수강 신청"),
    "휴학": ("휴학",),
    "복학": ("복학",),
    "장학": ("장학", "장학금"),
    # "등록" (bare) used to be a variant here too, but it matches ~2.8k-9.7k
    # rows in the large chunk tables on its own (measured directly against
    # content_tsv) -- ranking + sorting that many rows blew the lexical RPC's
    # statement timeout whenever a query also triggered another group (e.g.
    # "계절수업" -> schedule_005). Keep only the compound term.
    "등록금": ("등록금",),
    "성적": ("성적", "평점", "평균평점"),
    "교직": ("교직", "교직과정"),
    "현장실습": ("현장실습", "현장실습학기제"),
    # Bare "생활관"/"기숙사" measured at 300-800+ rows each in the large chunk
    # tables; combined with the compound term in one OR-query that pushed
    # lexical search over its statement timeout. The compound term alone
    # already matches the eval's expected documents, so keep only that.
    "생활관": ("학생생활관",),
    "계절수업": ("계절수업",),
    "외국인유학생": ("외국인유학생", "외국인 유학생", "외국인 신입생", "외국인 학위과정"),
    # Bare "증명서" alone matches 2,300-2,700 rows in rag/notice_chunks --
    # comparable to the "등록"/"졸업"/"전공" danger zone above -- so only
    # narrower phrase/compound variants go in the OR-query. "증명서 발급" as a
    # quoted adjacent-phrase is far rarer (16-142 rows per table) and safe.
    # Covers both how a question might phrase the kiosk ("자동발급기") and
    # how the source page actually phrases it ("무인발급기(기)"), which don't
    # share a literal substring so plain full-text search can't bridge them.
    "증명서발급": ("무인발급기", "무인발급기기", "자동발급기", "제증명", "증명서 발급"),
    # 실제 사용자 질문 사례("컴공학과사무실", 띄어쓰기 없는 구어체 줄임말)가
    # 이 그룹 없이는 검색 후보에 전혀 안 걸리는 것을 확인함 -- 임베딩도
    # "컴공"과 "컴퓨터·인공지능공학부"를 가깝게 못 보고, lexical fallback도
    # 공백 기준 토큰화라 붙여쓴 줄임말은 원문과 겹치는 부분이 없음.
    # "컴퓨터공학과"/"컴퓨터공학부"/"인공지능공학부"는 단독으로 1,400~1,900행씩
    # 매치돼 위 "증명서"급 위험 구간에 가까워 실제 검색어(OR 대상)에서는 빼고
    # LEXICAL_EXCLUDED_VARIANTS로 트리거 전용 처리. "컴퓨터·인공지능공학부"는
    # 개설학과 원문 명칭이라 그대로 둬도 인공지능공학부와 매치 집합이 거의
    # 겹쳐 추가 위험이 크지 않음(측정: 최대 1,405행, 안전 구간).
    "컴공학과": (
        "컴공",
        "컴퓨터공학과",
        "컴퓨터공학부",
        "인공지능공학부",
        "컴퓨터·인공지능공학부",
        "컴퓨터인공지능공학부",
    ),
}

STRICT_QUERY_TERMS = {
    "복수전공",
    "부전공",
    "마이크로전공",
    "전과",
    "학점",
    "수강신청",
    "휴학",
    "복학",
    "장학",
    "등록금",
    "성적",
    "교직",
    "현장실습",
}

DATASET_PRIORITIES = {
    "match_rule_documents": 1.00,
    "match_pknu_notice_documents": 0.70,
    "match_pknu_student_life_documents": 0.70,
    "match_rag_documents": 0.40,
}

# Query-time dataset routing. 특정 키워드가 질문에 있으면 관련 dataset의
# priority에 boost를 얹어서 상위로 끌어올림. 여러 규칙이 매칭되면 합산.
# 시연 필수 3개(Q1 졸업학점, Q2 졸업유예, Q3 캡스톤)에 회귀 없이 Q4(복수전공)
# 개선을 노림.
DATASET_BOOST_RULES: tuple[tuple[tuple[str, ...], Dict[str, float]], ...] = (
    (
        (
            "휴학", "복학", "결석", "출석", "재수강", "재이수", "전과",
            "졸업요건", "복수전공", "부전공", "학사경고", "학점",
            "학사학위취득유예", "졸업유예",
        ),
        {"match_rule_documents": 0.15, "match_pknu_student_life_documents": 0.10},
    ),
    (
        (
            "셔틀", "생활관", "기숙사", "도서관", "식당",
            "보건진료소", "연락처", "사무실", "전화",
        ),
        # "국립부경대학교 학칙" 같은 거대 허브 문서는 rule 데이터셋 전체에
        # 균일하게 걸리는 DATASET_PRIORITIES=1.00 덕에, 연락처류 질문과는
        # 무관한 조항이라도 다른 데이터셋의 훨씬 더 구체적인 문서를 상위
        # 랭킹에서 밀어내는 사례가 실측으로 확인됨(예: "컴퓨터·인공지능공학부
        # 사무실 연락처" 질문에서 학칙 조항이 1~2위, 실제 연락처 문서가 6위).
        # 위쪽 boost와 대칭으로 규정 데이터셋에는 페널티를 줘서 상쇄한다.
        {"match_pknu_student_life_documents": 0.15, "match_rule_documents": -0.35},
    ),
    (
        ("캡스톤", "학부 사무실", "학과 사무실"),
        {"match_rag_documents": 0.10, "match_rule_documents": -0.35},
    ),
)

SOURCE_KIND_PRIORITIES = {
    "post": 1.00,
    "page": 1.00,
    "html": 1.00,
    "attachment": 0.65,
    "archive_member": 0.55,
}

# Reciprocal Rank Fusion for hybrid (vector + lexical/BM25-style) retrieval.
# The embedding model discriminates formal Korean administrative text poorly:
# the one chunk that actually answers "복수전공 신청 조건" ranks ~160th by
# cosine similarity, well outside any vector top-K we could afford to fetch.
# A Postgres full-text ("simple" config) search on the same chunks catches
# exact-term matches the embedding misses. Lexical-only hits have no cosine
# similarity, so we approximate one from their BM25-ish rank via RRF and feed
# them into the existing candidate pool/scoring pipeline unchanged.
_RRF_K = 60
_LEXICAL_SIMILARITY_CEILING = 0.75


def _lexical_rrf_norm(rank_index: int) -> float:
    """0-based rank -> RRF weight, normalized against the best-possible (rank 0) value."""
    return (_RRF_K + 1) / (_RRF_K + rank_index + 1)


def _lexical_synthetic_similarity(rank_index: int, min_similarity: float) -> float:
    """Approximate a cosine-similarity-like score for a lexical-only hit.

    Deliberately capped below a genuine strong vector match (~0.85+) so a
    lexical hit can outrank weakly-matched vector noise without silently
    overriding rows the embedding model was actually confident about.
    """
    norm = _lexical_rrf_norm(rank_index)
    ceiling = max(min_similarity, _LEXICAL_SIMILARITY_CEILING)
    return min_similarity + norm * (ceiling - min_similarity)


# Bare words that are members of a QUERY_TERM_GROUPS entry but, measured
# directly against content_tsv, match thousands of rows in the largest chunk
# tables (rag_chunks/pknu_notice_chunks) on their own -- e.g. bare "졸업"
# alone needed 4.7-5.4s just to rank, right at (and sometimes past) the
# lexical RPC's statement timeout. They still need to stay in
# QUERY_TERM_GROUPS itself: other logic (_query_mismatch_flags /
# _dataset_mismatch_flags, e.g. the 졸업+학점 combo check) relies on the bare
# form to detect that a question is "about" that concept at all. Only the
# lexical OR-query builder below excludes them, since it's the one place a
# single overly-common token turns into a near-full-table scan.
LEXICAL_EXCLUDED_VARIANTS = {"졸업", "전공", "컴퓨터공학과", "컴퓨터공학부", "인공지능공학부"}

# Filler words that carry no retrieval signal but frequently show up in
# natural Korean questions. websearch_to_tsquery ANDs every remaining word
# together, so leaving these in silently zeroes out the match (the source
# chunk contains "학사관리과"/"증명서" but never literally "관련" next to it).
_LEXICAL_STOPWORDS = {
    "관련", "관련해서", "관련된", "관하여", "대해", "대해서", "대한",
    "알려줘", "알려주세요", "알려줄래요", "알려주실래요",
    "궁금해요", "궁금합니다", "궁금한데요", "궁금해",
    "어디에", "어디서", "어디", "어떻게", "무엇인가요", "뭐예요", "뭔가요",
    "있나요", "있어요", "있습니까", "됩니까", "되나요", "인가요", "인가",
    "하나요", "합니까", "하는지", "하는가요",
    "부탁드립니다", "부탁해요", "부탁드려요", "싶어요", "싶습니다",
}

# Korean particles attach directly to the noun with no space (문의처+를,
# 도서관+에), so a literal AND match needs them stripped first. Longest
# suffix first so e.g. "으로부터" doesn't get half-stripped to "로부터".
_LEXICAL_PARTICLE_SUFFIXES = tuple(
    sorted(
        {
            "으로부터", "에서부터", "에게서",
            "이라서", "라서", "이라도", "라도", "이라는", "라는", "이라고", "라고",
            "에서", "으로", "부터", "까지", "이나", "한테", "에게",
            "와는", "과는",
            "은", "는", "이", "가", "을", "를", "의", "에", "로", "와", "과", "도", "만", "나",
        },
        key=len,
        reverse=True,
    )
)


def _lexical_fallback_query(query_text: str) -> str:
    """Best-effort AND-query for questions that hit no QUERY_TERM_GROUPS entry.

    This only ever *removes* filler tokens and particle suffixes from the
    existing AND-of-raw-sentence fallback -- it never switches to OR -- so it
    can't reintroduce the near-full-table-scan timeout risk that
    LEXICAL_EXCLUDED_VARIANTS guards against. It can only make an
    already-safe AND query match in more cases, by narrowing the token list
    down to the words actually likely to appear next to the answer.
    """
    tokens: list[str] = []
    for raw_token in _normalize_text(query_text).split(" "):
        token = raw_token.strip("?!.,~()[]\"'")
        if not token or token in _LEXICAL_STOPWORDS:
            continue
        for suffix in _LEXICAL_PARTICLE_SUFFIXES:
            if len(token) > len(suffix) + 1 and token.endswith(suffix):
                token = token[: -len(suffix)]
                break
        if len(token) >= 2:
            tokens.append(token)
    return " ".join(dict.fromkeys(tokens))


def _lexical_query_text(
    query_text: Optional[str],
    query_terms: list[tuple[str, tuple[str, ...]]],
) -> str:
    """Build a websearch_to_tsquery-friendly OR-query from known term synonyms.

    Plain full-text search only matches literal tokens, but the same concept
    often shows up under a different word across datasets (question says
    "복수전공", the actual regulation says "다전공"). QUERY_TERM_GROUPS already
    encodes these synonym sets for the mismatch-penalty logic above, so reuse
    it here to OR all known variants together instead of AND-ing the raw
    question text, which would frequently match nothing at all.

    _query_term_groups() matches by substring, so a query like "복수전공" also
    matches the generic "전공" group ("전공" is a substring of "복수전공"). That
    is harmless for the penalty logic but disastrous here: OR-ing in a very
    common bare word like "전공" turns this into a near-full-table scan on the
    largest chunk tables and blows the statement timeout. Drop any matched
    term that is itself a substring of another, more specific matched term.
    """
    specific_terms = [
        (term, variants)
        for term, variants in query_terms
        if not any(term != other and term in other for other, _ in query_terms)
    ]
    if not specific_terms:
        return _lexical_fallback_query(query_text or "") or _normalize_text(query_text or "")
    parts: list[str] = []
    for _, variants in specific_terms:
        for variant in variants:
            variant = variant.strip()
            if not variant or variant in LEXICAL_EXCLUDED_VARIANTS:
                continue
            parts.append(f'"{variant}"' if " " in variant else variant)
    if not parts:
        return _lexical_fallback_query(query_text or "") or _normalize_text(query_text or "")
    return " OR ".join(dict.fromkeys(parts))


class Reranker(Protocol):
    def score(self, question: str, rows: List[Dict[str, Any]]) -> List[float]:
        ...


def build_supabase_client(url: str, key: str) -> Client:
    return create_client(url, key)


def _vector_literal(vec: List[float]) -> str:
    """pgvector accepts text literal '[v1,v2,...]'."""
    return "[" + ",".join(repr(float(v)) for v in vec) + "]"


def _similarity(row: Dict[str, Any]) -> float:
    try:
        return float(row.get("similarity") or 0.0)
    except (TypeError, ValueError):
        return 0.0


def _priority_score(row: Dict[str, Any]) -> float:
    metadata = row.get("metadata") or {}
    value = row.get("priority_score", metadata.get("priority_score"))
    try:
        return float(value or 0.0)
    except (TypeError, ValueError):
        return 0.0


def _dataset_priority(row: Dict[str, Any]) -> float:
    override = row.get("_boosted_dataset_priority")
    if override is not None:
        try:
            return float(override)
        except (TypeError, ValueError):
            pass
    metadata = row.get("metadata") or {}
    rpc_name = str(metadata.get("rpc_name") or "")
    return DATASET_PRIORITIES.get(rpc_name, 0.50)


def _dataset_priority_boost(rpc_name: str, query_text: Optional[str]) -> float:
    if not query_text:
        return 0.0
    text = _normalize_text(query_text)
    if not text:
        return 0.0
    boost = 0.0
    for keywords, boosts in DATASET_BOOST_RULES:
        if any(kw in text for kw in keywords):
            boost += boosts.get(rpc_name, 0.0)
    return boost


def _source_kind_priority(row: Dict[str, Any]) -> float:
    metadata = row.get("metadata") or {}
    source_kind = str(metadata.get("source_kind") or "").strip().lower()
    source_ext = str(metadata.get("source_ext") or "").strip().lower()
    if source_ext in {".html", ".htm", ".json"} and not source_kind:
        source_kind = "html"
    return SOURCE_KIND_PRIORITIES.get(source_kind, 0.70)


# A cross-encoder reranker trained on single-topic passage relevance tends to
# score a chunk that mentions one phone number in a clean, focused sentence
# higher than a chunk that is actually the authoritative directory/contact
# page for that number, but lists it among several other facts (other
# extensions, a fax number, an unrelated program's number) -- the dense
# chunk reads as "less about" the query even though it is the better source.
# Observed live: "컴공학과사무실 전화번호 알려줘" cited a notice that happened to
# mention one CE department number in passing, over the department's own
# contact-directory chunk (6 numbers: 3 office lines, a program line, 2 fax
# numbers) -- reranker preferred the single coincidental mention. Detect the
# directory shape directly (several distinct phone numbers in one chunk) and
# nudge it back up *after* reranking, so the fix doesn't get diluted by
# reranker_weight the way a priority_score change would (that only feeds the
# ~20% "initial_score" side of the blend, not the ~80% reranker side).
_PHONE_NUMBER_RE = re.compile(r"\d{2,4}[-–]\d{3,4}[-–]\d{4}")
CONTACT_DIRECTORY_MIN_PHONE_NUMBERS = 2
CONTACT_DIRECTORY_BONUS = 0.06


def _is_contact_directory_row(row: Dict[str, Any]) -> bool:
    content = str(row.get("content") or "")
    numbers = set(_PHONE_NUMBER_RE.findall(content))
    return len(numbers) >= CONTACT_DIRECTORY_MIN_PHONE_NUMBERS


def _query_mismatch_penalty(row: Dict[str, Any]) -> float:
    """Soft penalty for query-term mismatch flags (see _query_mismatch_flags).

    Previously these flags caused a hard drop, which could wipe out 90%+ of
    candidates for common terms (e.g. "복수전공") whenever no chunk repeated
    the exact keyword, even when the chunk was otherwise the best match
    available. A penalty lets better-matching rows win naturally while still
    surfacing something instead of "관련 정보를 찾을 수 없습니다" when nothing
    better exists.
    """
    flags = row.get("_query_mismatch_flags") or []
    penalty = 0.0
    for flag in flags:
        if flag.startswith("missing_strict_query_terms") or flag == "no_query_term_overlap":
            penalty = max(penalty, 0.35)
        elif flag == "missing_graduation_credit_terms":
            penalty = max(penalty, 0.25)
    return penalty


def _final_score(
    row: Dict[str, Any],
    priority_weight: float,
    dataset_priority_weight: float,
    source_kind_weight: float,
) -> float:
    bounded_weight = max(0.0, min(1.0, priority_weight))
    bounded_dataset_weight = max(0.0, min(1.0, dataset_priority_weight))
    bounded_source_kind_weight = max(0.0, min(1.0, source_kind_weight))
    semantic_weight = max(
        0.0,
        1.0 - bounded_weight - bounded_dataset_weight - bounded_source_kind_weight,
    )
    score = (
        _similarity(row) * semantic_weight
        + _priority_score(row) * bounded_weight
        + _dataset_priority(row) * bounded_dataset_weight
        + _source_kind_priority(row) * bounded_source_kind_weight
    )
    return max(0.0, score - _query_mismatch_penalty(row))


def _normalize_text(text: str) -> str:
    return " ".join(str(text or "").replace("\u00a0", " ").split()).strip()


def _title_for_row(row: Dict[str, Any]) -> str:
    metadata = row.get("metadata") or {}
    return _normalize_text(
        metadata.get("doc_title")
        or metadata.get("source_file")
        or metadata.get("title")
        or row.get("title")
        or row.get("source_slug")
        or ""
    )


def _noise_flags(row: Dict[str, Any]) -> list[str]:
    text = _normalize_text(row.get("content") or row.get("text") or "")
    title = _title_for_row(row)
    if not text:
        return ["empty"]

    tokens = re.findall(r"[0-9A-Za-z\uac00-\ud7a3]+", text.lower())
    unique_tokens = set(tokens)
    hangul_count = len(re.findall(r"[\uac00-\ud7a3]", text))
    digit_count = len(re.findall(r"\d", text))
    dot_count = text.count(".") + text.count("·") + text.count("_")
    compact_len = max(1, len(re.sub(r"\s+", "", text)))
    lower_text = text.lower()
    flags: list[str] = []
    keyword_hits = sum(1 for keyword in ACADEMIC_KEYWORDS if keyword in text)

    if len(text) < 100 and len(unique_tokens) <= 6 and keyword_hits < 3:
        flags.append("metadata_stub")
    if dot_count / compact_len >= 0.20:
        flags.append("punctuation_heavy")
    if digit_count / compact_len >= 0.60 and hangul_count < 20:
        flags.append("numeric_heavy")
    if re.fullmatch(r"[\d\s.,:;~\-–—·ㆍ/()]+", text):
        flags.append("no_words")
    if any(phrase.lower() in lower_text for phrase in NOISE_PHRASES) and len(text) < 300:
        flags.append("template_or_form_noise")

    title_compact = re.sub(r"\s+", "", title)
    text_compact = re.sub(r"\s+", "", text)
    generic_titles = {re.sub(r"\s+", "", item) for item in GENERIC_STUB_TITLES}
    if title_compact in generic_titles and len(text) < 200:
        flags.append("generic_title_stub")
    if title_compact and text_compact and title_compact in text_compact:
        remainder = text_compact.replace(title_compact, "")
        if len(text) < 180 and len(remainder) <= 20:
            flags.append("title_only_stub")

    # Keep short chunks only when they contain enough concrete academic signal.
    if len(text) < 80 and keyword_hits < 2:
        flags.append("weak_short_chunk")

    # 반복 문자/자모 스팸 ("ㅇㅇㅇㅇㅇ", "!!!!!", "~~~~~")
    if _REPEATED_CHAR_RE.search(text):
        flags.append("repeated_char_spam")
    if _STANDALONE_JAMO_RE.search(text):
        flags.append("standalone_jamo_spam")

    return flags


def _is_noisy_row(row: Dict[str, Any]) -> bool:
    return bool(_noise_flags(row))


def _query_term_groups(query_text: Optional[str]) -> list[tuple[str, tuple[str, ...]]]:
    normalized = _normalize_text(query_text or "")
    if not normalized:
        return []
    return [
        (term, variants)
        for term, variants in QUERY_TERM_GROUPS.items()
        if any(variant in normalized for variant in variants)
    ]


def _query_mismatch_flags(
    row: Dict[str, Any],
    query_terms: list[tuple[str, tuple[str, ...]]],
) -> list[str]:
    if not query_terms:
        return []

    haystack = _normalize_text(f"{_title_for_row(row)} {row.get('content') or ''}")
    missing_strict = []
    matched = 0
    matched_terms: set[str] = set()
    for term, variants in query_terms:
        if any(variant in haystack for variant in variants):
            matched += 1
            matched_terms.add(term)
        elif term in STRICT_QUERY_TERMS:
            missing_strict.append(term)

    flags: list[str] = []
    if missing_strict:
        flags.append("missing_strict_query_terms:" + ",".join(missing_strict))
    if len(query_terms) >= 2 and matched == 0:
        flags.append("no_query_term_overlap")
    term_names = {term for term, _ in query_terms}
    if {"졸업", "학점"}.issubset(term_names) and not {"졸업", "학점"}.issubset(
        matched_terms
    ):
        flags.append("missing_graduation_credit_terms")
    return flags


def _dataset_mismatch_flags(
    row: Dict[str, Any],
    query_terms: list[tuple[str, tuple[str, ...]]],
) -> list[str]:
    term_names = {term for term, _ in query_terms}
    if not term_names:
        return []

    metadata = row.get("metadata") or {}
    rpc_name = str(metadata.get("rpc_name") or "")
    haystack = _normalize_text(f"{_title_for_row(row)} {row.get('content') or ''}")
    flags: list[str] = []

    if {"졸업", "학점"}.issubset(term_names):
        if not any(
            keyword in haystack
            for keyword in ("졸업요건", "졸업 소요학점", "소요학점", "교육과정 편성")
        ):
            flags.append("not_suitable_for_graduation_credit")

    return flags


def _row_uri(row: Dict[str, Any]) -> str:
    metadata = row.get("metadata") or {}
    return (
        row.get("uri")
        or row.get("url")
        or metadata.get("doc_url")
        or metadata.get("source_page_url")
        or metadata.get("attachment_url")
        or ""
    )


def _url_key(row: Dict[str, Any]) -> str:
    """Per-URL cap 용 key. 쿼리스트링/앵커 제거해서 같은 문서 다른 뷰 통합.

    URL만으로 묶으면 안 된다 -- `www.pknu.ac.kr/main/434`처럼 서로 다른
    문서 여러 개가 같은 CMS 랜딩페이지 URL을 공유하는 경우가 실제로 있다
    (dedup 로직에서 이미 겪은 것과 동일한 문제). URL 하나로 묶으면, 그
    URL을 공유하는 무관한 문서가 이미 max_chunks_per_url 자리를 다
    채워버려서 정작 그 URL의 진짜 문서가 밀려나는 일이 생긴다 -- 오늘
    부서 연락처 디렉터리를 잘게 쪼갠 뒤 실제로 겪은 사례. 제목까지 묶어야
    "같은 문서의 여러 청크"만 캡 대상이 된다.
    """
    uri = re.sub(r"[?#].*$", "", _normalize_text(_row_uri(row)).lower())
    title = _normalize_text(_title_for_row(row)).lower()
    if uri:
        return f"url:{uri}|title:{title}"
    return f"title:{title}"


def _dedupe_key(row: Dict[str, Any]) -> str:
    """정확히 같은 chunk 제거용 (같은 chunk가 여러 RPC에서 반환되는 경우 대비)."""
    uri = _row_uri(row)
    title = _title_for_row(row)
    metadata = row.get("metadata") or {}
    content = str(row.get("content") or "")
    if content:
        digest = hashlib.sha1(
            _normalize_text(content)[:500].encode("utf-8", errors="ignore")
        ).hexdigest()
        return f"{uri}|{title}|{digest}"

    for key in ("id", "chunk_id", "document_id"):
        value = row.get(key) or metadata.get(key)
        if value:
            return f"{key}:{value}"
    return f"{uri}|{title}"


def _is_lexical_only(row: Dict[str, Any]) -> bool:
    return bool(row.get("_lexical_only"))


def _add_row(
    selected: List[Dict[str, Any]],
    seen: set[str],
    url_counts: Dict[str, int],
    row: Dict[str, Any],
    *,
    max_chunks_per_url: int,
    lexical_url_counts: Optional[Dict[str, int]] = None,
    max_lexical_chunks_per_url: Optional[int] = None,
) -> bool:
    key = _dedupe_key(row)
    if key in seen:
        return False
    url_key = _url_key(row)
    if url_counts.get(url_key, 0) >= max_chunks_per_url:
        return False
    if (
        lexical_url_counts is not None
        and max_lexical_chunks_per_url is not None
        and _is_lexical_only(row)
        and lexical_url_counts.get(url_key, 0) >= max_lexical_chunks_per_url
    ):
        return False
    seen.add(key)
    url_counts[url_key] = url_counts.get(url_key, 0) + 1
    if lexical_url_counts is not None and _is_lexical_only(row):
        lexical_url_counts[url_key] = lexical_url_counts.get(url_key, 0) + 1
    selected.append(row)
    return True


def _cap_per_url(
    rows: List[Dict[str, Any]],
    *,
    max_chunks_per_url: int,
    max_lexical_chunks_per_url: Optional[int] = None,
) -> List[Dict[str, Any]]:
    """Preserve input order, keep at most `max_chunks_per_url` rows per URL.

    Lexical-only hits (no genuine vector match; similarity is a BM25-rank
    approximation, see _lexical_synthetic_similarity) get an extra, tighter
    per-URL allowance on top of the general cap. Without this, one broad
    document that happens to contain several query keywords (e.g. an
    all-topics "student life guide" ebook chunked into 2000+ pieces) can
    claim most of its URL's chunk slots via lexical coincidence alone,
    crowding out chunks from other, more specifically relevant documents.
    """
    counts: Dict[str, int] = {}
    lexical_counts: Dict[str, int] = {}
    kept: List[Dict[str, Any]] = []
    for row in rows:
        url_key = _url_key(row)
        if counts.get(url_key, 0) >= max_chunks_per_url:
            continue
        if (
            max_lexical_chunks_per_url is not None
            and _is_lexical_only(row)
            and lexical_counts.get(url_key, 0) >= max_lexical_chunks_per_url
        ):
            continue
        counts[url_key] = counts.get(url_key, 0) + 1
        if _is_lexical_only(row):
            lexical_counts[url_key] = lexical_counts.get(url_key, 0) + 1
        kept.append(row)
    return kept


def _rerank_candidates(
    *,
    question: str,
    candidates: List[Dict[str, Any]],
    top_k: int,
    max_chunks_per_url: int,
    reranker: Optional[Reranker],
    reranker_weight: float,
    priority_weight: float,
    dataset_priority_weight: float,
    source_kind_weight: float,
    max_lexical_chunks_per_url: Optional[int] = None,
) -> List[Dict[str, Any]]:
    if not candidates:
        return []

    if not reranker or not question.strip():
        ordered = sorted(
            candidates,
            key=lambda row: _final_score(
                row,
                priority_weight,
                dataset_priority_weight,
                source_kind_weight,
            ),
            reverse=True,
        )
        return _cap_per_url(
            ordered,
            max_chunks_per_url=max_chunks_per_url,
            max_lexical_chunks_per_url=max_lexical_chunks_per_url,
        )[:top_k]

    try:
        raw_scores = reranker.score(question, candidates)
    except Exception:
        logger.exception("retrieval: reranker failed, falling back to initial scores")
        ordered = sorted(
            candidates,
            key=lambda row: _final_score(
                row,
                priority_weight,
                dataset_priority_weight,
                source_kind_weight,
            ),
            reverse=True,
        )
        return _cap_per_url(
            ordered,
            max_chunks_per_url=max_chunks_per_url,
            max_lexical_chunks_per_url=max_lexical_chunks_per_url,
        )[:top_k]

    normalized_scores = normalize_scores(raw_scores)
    bounded_reranker_weight = max(0.0, min(1.0, reranker_weight))
    initial_weight = 1.0 - bounded_reranker_weight
    rescored: List[Dict[str, Any]] = []
    for row, rerank_score in zip(candidates, normalized_scores):
        copied = dict(row)
        initial_score = _final_score(
            copied,
            priority_weight,
            dataset_priority_weight,
            source_kind_weight,
        )
        rerank_final_score = (
            rerank_score * bounded_reranker_weight
            + initial_score * initial_weight
        )
        # Applied *after* the reranker blend, not folded into initial_score,
        # so it isn't diluted by (1 - reranker_weight) -- see
        # _is_contact_directory_row's docstring for why this lives here.
        if _is_contact_directory_row(copied):
            rerank_final_score += CONTACT_DIRECTORY_BONUS
        copied["rerank_score"] = rerank_score
        copied["rerank_final_score"] = rerank_final_score
        rescored.append(copied)

    rescored.sort(key=lambda row: float(row.get("rerank_final_score") or 0.0), reverse=True)
    return _cap_per_url(
        rescored,
        max_chunks_per_url=max_chunks_per_url,
        max_lexical_chunks_per_url=max_lexical_chunks_per_url,
    )[:top_k]


def _process_candidate_row(
    row: Dict[str, Any],
    rpc_name: str,
    query_text: Optional[str],
    query_terms: list[tuple[str, tuple[str, ...]]],
    priority_weight: float,
    dataset_priority_weight: float,
    source_kind_weight: float,
) -> tuple[Optional[Dict[str, Any]], str]:
    """Shared per-row pipeline, used for both vector and lexical RPC rows.

    Returns (row, outcome). outcome is "noise" or "dataset_mismatch" when the
    row is dropped (row is None in that case), "query_mismatch" when it is
    kept but penalized, or "ok" otherwise.
    """
    copied = dict(row)
    metadata = dict(copied.get("metadata") or {})
    metadata.setdefault("rpc_name", rpc_name)
    copied["metadata"] = metadata

    if _noise_flags(copied):
        return None, "noise"

    query_flags = _query_mismatch_flags(copied, query_terms)
    if query_flags:
        copied["_query_mismatch_flags"] = query_flags

    if _dataset_mismatch_flags(copied, query_terms):
        return None, "dataset_mismatch"

    base_dataset_priority = DATASET_PRIORITIES.get(rpc_name, 0.50)
    boost = _dataset_priority_boost(rpc_name, query_text)
    copied["_boosted_dataset_priority"] = max(0.0, min(1.0, base_dataset_priority + boost))
    copied["priority_score"] = _priority_score(copied)
    copied["dataset_priority"] = _dataset_priority(copied)
    copied["final_score"] = _final_score(
        copied, priority_weight, dataset_priority_weight, source_kind_weight
    )
    return copied, ("query_mismatch" if query_flags else "ok")


def search(
    client: Client,
    *,
    rpc_names: List[str],
    embedding: List[float],
    top_k: int,
    first_stage_k: int,
    min_similarity: float,
    priority_weight: float = 0.30,
    dataset_priority_weight: float = 0.15,
    source_kind_weight: float = 0.10,
    reranker: Optional[Reranker] = None,
    reranker_weight: float = 0.80,
    max_chunks_per_url: int = 2,
    max_lexical_chunks_per_url: Optional[int] = None,
    query_text: Optional[str] = None,
    metadata_filter: Optional[Dict[str, Any]] = None,
) -> List[Dict[str, Any]]:
    """Fan out across RPCs, merge rows, then return a diverse top_k set.

    Each RPC must accept the same (query_embedding, match_count, min_similarity,
    metadata_filter) signature and return rows with a `similarity` field. RPCs
    apply min_similarity in DB, so the merged set is already filtered. A failure
    in one RPC is logged at WARN and skipped; partial results still flow.
    """
    query_terms = _query_term_groups(query_text)
    lexical_query = _lexical_query_text(query_text, query_terms)
    candidate_count = max(first_stage_k, top_k)
    payload = {
        "query_embedding": _vector_literal(embedding),
        "match_count": candidate_count,
        "min_similarity": min_similarity,
        "metadata_filter": metadata_filter or {},
    }

    per_rpc_rows: List[List[Dict[str, Any]]] = []
    merged: List[Dict[str, Any]] = []
    for rpc_name in rpc_names:
        try:
            started = time.perf_counter()
            response = client.rpc(rpc_name, payload).execute()
            elapsed_ms = (time.perf_counter() - started) * 1000
        except Exception:
            logger.warning("retrieval: rpc=%s failed, skipping", rpc_name, exc_info=True)
            continue

        rows: List[Dict[str, Any]] = []
        filtered_noise = 0
        penalized_query_mismatch = 0
        filtered_dataset_mismatch = 0
        for row in response.data or []:
            processed, outcome = _process_candidate_row(
                row,
                rpc_name,
                query_text,
                query_terms,
                priority_weight,
                dataset_priority_weight,
                source_kind_weight,
            )
            if outcome == "noise":
                filtered_noise += 1
                if logger.isEnabledFor(logging.DEBUG):
                    logger.debug(
                        "retrieval: filtered_noise rpc=%s title=%r sim=%.4f",
                        rpc_name,
                        _title_for_row(row)[:120],
                        _similarity(row),
                    )
                continue
            if outcome == "dataset_mismatch":
                filtered_dataset_mismatch += 1
                if logger.isEnabledFor(logging.DEBUG):
                    logger.debug(
                        "retrieval: filtered_dataset_mismatch rpc=%s title=%r sim=%.4f",
                        rpc_name,
                        _title_for_row(row)[:120],
                        _similarity(row),
                    )
                continue
            if outcome == "query_mismatch":
                penalized_query_mismatch += 1
            rows.append(processed)

        # ── Lexical (BM25-style full-text) channel ───────────────────────
        # Runs against the same table via `<rpc_name>_lexical` and is merged
        # by rank (RRF) rather than raw score, since ts_rank_cd isn't
        # comparable to cosine similarity. Only rows the vector search missed
        # entirely are added here; rows both channels found already made the
        # vector top-K on their own merit and keep their real similarity.
        lexical_added = 0
        lexical_boosted = 0
        if lexical_query:
            rows_by_key = {_dedupe_key(row): row for row in rows}
            vector_keys = set(rows_by_key)
            lexical_rpc_name = f"{rpc_name}_lexical"
            try:
                lexical_response = client.rpc(
                    lexical_rpc_name,
                    {"query_text": lexical_query, "match_count": candidate_count},
                ).execute()
            except Exception:
                logger.warning(
                    "retrieval: lexical rpc=%s failed, skipping", lexical_rpc_name, exc_info=True
                )
                lexical_response = None

            rank_index = 0
            for row in (lexical_response.data if lexical_response else None) or []:
                processed, outcome = _process_candidate_row(
                    row,
                    rpc_name,
                    query_text,
                    query_terms,
                    priority_weight,
                    dataset_priority_weight,
                    source_kind_weight,
                )
                if outcome in ("noise", "dataset_mismatch") or processed is None:
                    continue
                dedupe_key = _dedupe_key(processed)
                if dedupe_key in vector_keys:
                    # Vector search already found this chunk, but possibly at
                    # a mediocre similarity that buries a strong exact-term
                    # match (e.g. a short, keyword-dense chunk the embedding
                    # model doesn't score highly on its own). A high BM25
                    # rank here means the chunk deserves at least the score a
                    # lexical-only hit at that rank would get -- take
                    # whichever of the two signals is stronger instead of
                    # always deferring to the vector channel.
                    existing = rows_by_key[dedupe_key]
                    lexical_equivalent = _lexical_synthetic_similarity(
                        rank_index, min_similarity
                    )
                    if lexical_equivalent > _similarity(existing):
                        existing["similarity"] = lexical_equivalent
                        existing["priority_score"] = _priority_score(existing)
                        existing["dataset_priority"] = _dataset_priority(existing)
                        existing["final_score"] = _final_score(
                            existing, priority_weight, dataset_priority_weight, source_kind_weight
                        )
                        lexical_boosted += 1
                    rank_index += 1
                    continue
                processed["similarity"] = _lexical_synthetic_similarity(
                    rank_index, min_similarity
                )
                processed["_lexical_only"] = True
                processed["priority_score"] = _priority_score(processed)
                processed["dataset_priority"] = _dataset_priority(processed)
                processed["final_score"] = _final_score(
                    processed, priority_weight, dataset_priority_weight, source_kind_weight
                )
                rows.append(processed)
                rows_by_key[dedupe_key] = processed
                vector_keys.add(dedupe_key)
                lexical_added += 1
                rank_index += 1

        rows.sort(
            key=lambda row: _final_score(
                row,
                priority_weight,
                dataset_priority_weight,
                source_kind_weight,
            ),
            reverse=True,
        )
        logger.info(
            "retrieval: rpc=%s rows=%d filtered_noise=%d penalized_query_mismatch=%d filtered_dataset_mismatch=%d lexical_added=%d lexical_boosted=%d latency_ms=%.1f top_similarity=%.4f top_priority=%.4f top_dataset_priority=%.2f top_source_kind_priority=%.2f top_final=%.4f priority_weight=%.2f dataset_priority_weight=%.2f source_kind_weight=%.2f",
            rpc_name,
            len(rows),
            filtered_noise,
            penalized_query_mismatch,
            filtered_dataset_mismatch,
            lexical_added,
            lexical_boosted,
            elapsed_ms,
            _similarity(rows[0]) if rows else 0.0,
            _priority_score(rows[0]) if rows else 0.0,
            _dataset_priority(rows[0]) if rows else 0.0,
            _source_kind_priority(rows[0]) if rows else 0.0,
            _final_score(
                rows[0],
                priority_weight,
                dataset_priority_weight,
                source_kind_weight,
            )
            if rows
            else 0.0,
            priority_weight,
            dataset_priority_weight,
            source_kind_weight,
        )
        per_rpc_rows.append(rows)
        merged.extend(rows)

    candidates: List[Dict[str, Any]] = []
    seen: set[str] = set()
    url_counts: Dict[str, int] = {}
    lexical_url_counts: Dict[str, int] = {}

    # Keep one high-scoring row from each successful RPC before global ranking.
    # This prevents one noisy collection from crowding out regulations/notices.
    for rows in per_rpc_rows:
        if len(candidates) >= candidate_count:
            break
        for row in rows:
            if _add_row(
                candidates,
                seen,
                url_counts,
                row,
                max_chunks_per_url=max_chunks_per_url,
                lexical_url_counts=lexical_url_counts,
                max_lexical_chunks_per_url=max_lexical_chunks_per_url,
            ):
                break

    merged.sort(
        key=lambda row: _final_score(
            row,
            priority_weight,
            dataset_priority_weight,
            source_kind_weight,
        ),
        reverse=True,
    )
    for row in merged:
        if len(candidates) >= candidate_count:
            break
        _add_row(
            candidates,
            seen,
            url_counts,
            row,
            max_chunks_per_url=max_chunks_per_url,
            lexical_url_counts=lexical_url_counts,
            max_lexical_chunks_per_url=max_lexical_chunks_per_url,
        )

    selected = _rerank_candidates(
        question=query_text or "",
        candidates=candidates,
        top_k=top_k,
        max_chunks_per_url=max_chunks_per_url,
        reranker=reranker,
        reranker_weight=reranker_weight,
        priority_weight=priority_weight,
        dataset_priority_weight=dataset_priority_weight,
        source_kind_weight=source_kind_weight,
        max_lexical_chunks_per_url=max_lexical_chunks_per_url,
    )

    logger.info(
        "retrieval: merged=%d candidates=%d trimmed=%d top_sim=%.3f top_priority=%.3f top_dataset_priority=%.2f top_source_kind_priority=%.2f top_final=%.3f top_rerank=%.3f priority_weight=%.2f dataset_priority_weight=%.2f source_kind_weight=%.2f reranker=%s",
        len(merged),
        len(candidates),
        len(selected),
        _similarity(selected[0]) if selected else 0.0,
        _priority_score(selected[0]) if selected else 0.0,
        _dataset_priority(selected[0]) if selected else 0.0,
        _source_kind_priority(selected[0]) if selected else 0.0,
        _final_score(
            selected[0],
            priority_weight,
            dataset_priority_weight,
            source_kind_weight,
        )
        if selected
        else 0.0,
        float(selected[0].get("rerank_score") or 0.0) if selected else 0.0,
        priority_weight,
        dataset_priority_weight,
        source_kind_weight,
        bool(reranker),
    )
    if logger.isEnabledFor(logging.DEBUG):
        selected_summaries = []
        for index, row in enumerate(selected, start=1):
            metadata = row.get("metadata") or {}
            title = (
                metadata.get("doc_title")
                or metadata.get("source_file")
                or metadata.get("title")
                or row.get("title")
                or row.get("source_slug")
                or ""
            )
            selected_summaries.append(
                {
                    "index": index,
                    "rpc": metadata.get("rpc_name"),
                    "title": str(title)[:120],
                    "similarity": round(_similarity(row), 4),
                    "priority_score": round(_priority_score(row), 4),
                    "dataset_priority": round(_dataset_priority(row), 4),
                    "source_kind_priority": round(_source_kind_priority(row), 4),
                    "final_score": round(
                        _final_score(
                            row,
                            priority_weight,
                            dataset_priority_weight,
                            source_kind_weight,
                        ),
                        4,
                    ),
                    "rerank_score": round(float(row.get("rerank_score") or 0.0), 4),
                    "rerank_final_score": round(
                        float(row.get("rerank_final_score") or 0.0), 4
                    ),
                }
            )
        logger.debug("retrieval: selected=%s", selected_summaries)
    return selected
