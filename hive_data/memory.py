"""The named operations over the `memory` schema: storing and recalling.

What is here and what is deliberately not. lucent owns the memory service:
it turns text into an embedding, decides the data class and the tier, guards
the standing tier, holds the knowledge graph and prunes. None of that moves
here. What moves here is the part that was SQLite-specific - an FTS5 virtual
table for keywords and a scan that pulled every row's 4096 floats into numpy
to score cosine in Python - because neither survives the move to Postgres.

So these operations take an embedding as given and never generate one. The
model that produces it, and the credential for reaching that model, belong
behind lucent's API; a data-access layer that called out to an inference
service would be a layer every consumer has to configure an inference
service for.

The blend in `recall` is lucent's own, ported with its constants and its
bucket arithmetic unchanged. That is deliberate and it is the whole point of
the story: the only thing that changes is where the arithmetic runs. Whether
a better ranking should replace it is a separate decision with its own
evidence, and its own story.
"""

from __future__ import annotations

import math
import re
import time
from typing import Any, Mapping, Sequence

from . import _sql
from .core import _execute, _execute_returning, _fetch, _fetch_one
from .errors import ValueRefused
from .schema import qualified, select_list
from .unit import Unit

#: lucent's own, unchanged. A memory's score decays with a 30-day half-life
#: and never falls below half, so recency is a bounded multiplier on
#: similarity rather than a second ranking.
RECENCY_HALF_LIFE_DAYS = 30
RECENCY_FLOOR = 0.5
VECTOR_POOL = 20
KEYWORD_POOL = 10
DEFAULT_K = 5

#: How many keyword hits are asked for before the provenance filter is
#: applied. lucent asks FTS5 for `KEYWORD_POOL * 4` across the whole store
#: and only then keeps the ones belonging to the minds being read, so a mind
#: holding few rows can end up with fewer than `KEYWORD_POOL` candidates.
#: Carried across exactly, because this story ports the blend rather than
#: improving it - and improving it changes which memories arrive in every
#: mind's context, which is a judgement call that belongs with the evidence.
KEYWORD_SCAN = KEYWORD_POOL * 4

#: Postgres has no BM25, and `ts_rank` is not a rescaled BM25 - it is a
#: different formula on a different scale. Measured over the live corpus
#: with a real three-token query: FTS5's `-bm25()` returns 6.4 to 8.8, and
#: `ts_rank` over the same query returns 0.040 to 0.061. Roughly 150 to 1.
#:
#: That ratio is load-bearing in two places and invisible in both. The
#: backfill below adds `0.05 * keyword` to `cosine * recency`, so at FTS5's
#: scale the keyword term contributes about 0.37 against a combined score of
#: 0.2 to 0.8 - real weight - and at `ts_rank`'s scale it contributes 0.0025,
#: which is nothing. And the `bm` figure is rendered into the model's
#: injected context every turn by the contextual-retrieval hook, so a field
#: that kept its name and changed its magnitude by two orders would read as
#: the same number meaning something else.
#:
#: Monotonic, so nothing about the ordering within the keyword bucket
#: changes; this only restores the magnitude the surrounding arithmetic and
#: the hook were written against.
KEYWORD_SCALE = 150.0

#: The text search configuration the searchable column is built with. Named
#: here as the schema declares it, because a query has to be parsed with the
#: same configuration the document was, or the two sides stem differently
#: and a word matches itself and nothing else.
TEXT_CONFIG = "memory.hive_text"

#: lucent's stoplist, verbatim. It filters the *query*; the index keeps
#: every token, which is what FTS5 does. The two are not interchangeable: a
#: configuration that dropped stopwords from the documents as well would
#: silently stop matching query words this list happens to keep.
STOPWORDS = frozenset({
    "a", "an", "the", "and", "or", "but", "if", "of", "in", "on", "at",
    "to", "for", "from", "by", "with", "as", "is", "are", "was", "were",
    "be", "been", "being", "do", "does", "did", "have", "has", "had",
    "this", "that", "these", "those", "it", "its", "i", "you", "we",
    "they", "he", "she", "me", "my", "our", "your", "their", "them",
    "us", "what", "when", "where", "why", "how", "who", "which",
    "can", "could", "would", "should", "will", "shall", "may", "might",
    "just", "really", "very", "so", "also", "too", "any", "some", "all",
    "no", "not", "yes", "ok", "okay",
})

#: Every column a recall hands back, in lucent's own order. `content_search`
#: is declared private and so is never among them.
_READ = select_list("memories")


def terms(query: str) -> list[str]:
    """The words of a free-text query that are worth searching for.

    Tokenised to alphanumerics, which also means nothing a caller typed can
    reach the query parser as an operator: `to_tsquery` reads `&`, `|`, `!`,
    `:` and `<->` as syntax, and a bare apostrophe is a syntax error rather
    than a word.
    """
    found = [t.lower() for t in re.findall(r"[A-Za-z0-9_]+", query)]
    return [t for t in found if len(t) > 2 and t not in STOPWORDS]


def _tsquery(query: str) -> str | None:
    """A query's words as an OR-joined tsquery, or None if it has none.

    OR rather than AND, because that is what lucent does: any meaningful
    token contributes to the ranking, and a memory matching one word of six
    is a candidate rather than a miss.
    """
    found = terms(query)
    return " | ".join(found) if found else None


def _provenance(mind_id: str | None,
                mind_ids: Sequence[str] | None,
                start: int) -> tuple[str, list[Any]]:
    """The clause scoping a read to a set of minds, as SQL and arguments.

    Three cases, and the difference between the last two is a security
    boundary rather than a convenience:

    * Neither given means no restriction. The console's own pages and the
      nightly pruner read across the hive on purpose.
    * A list, which is how a mind reads its own memories plus the `shared`
      sentinel the hive-wide standing rules are written under. A single
      value could never express that pair.
    * An **empty or blank** selection matches nothing, and this is the part
      lucent gets wrong. Its test is `if mind_id:`, so the empty string an
      unset `MIND_ID` produces is falsy, the clause disappears entirely, and
      the read returns every mind's memories - the kids' boxes alongside the
      operator's. A scoping check that becomes a scoping bypass on exactly
      the value a missing environment variable produces. Blank means "no
      provenance at all" here, and matches nothing.
    """
    if mind_ids is not None:
        names = [str(m).strip() for m in mind_ids if str(m or "").strip()]
        if not names:
            return "1 = 0", []
        return f'"mind_id" = ANY(${start}::text[])', [names]
    if mind_id is None:
        return "", []
    named = str(mind_id).strip()
    if not named:
        return "1 = 0", []
    return f'"mind_id" = ${start}', [named]


def _norm(embedding: Sequence[float]) -> float:
    return math.sqrt(sum(float(v) * float(v) for v in embedding))


def _checked_query_vector(embedding: Sequence[float]) -> list[float]:
    """The query vector, refused if nothing can be measured against it.

    lucent returns `{"error": "zero_query_embedding"}` for this, which is a
    sentence rather than a score. Postgres is worse than a sentence: cosine
    distance against a zero vector is NaN, every comparison with NaN is
    false, so such a row slips past a `min_score` filter that was meant to
    exclude it and arrives with `cosine: NaN` - which `json.dumps` writes as
    a bare `NaN` that a strict reader rejects outright.
    """
    values = [float(v) for v in embedding]
    if not values:
        raise ValueRefused(
            "a recall was given an empty embedding. There is nothing to "
            "measure similarity against, and an empty vector is not a "
            "query that matches everything.")
    if _norm(values) == 0.0:
        raise ValueRefused(
            "a recall was given an all-zero embedding. Cosine distance "
            "against it is NaN rather than a number, NaN compares false "
            "against every threshold, and the result would arrive looking "
            "like a score. The embedding model failing is the usual cause.")
    return values


async def store(*, mind_id: str, content: str,
                embedding: Sequence[float] | None = None,
                tags: str = "", source: str | None = None,
                data_class: str | None = None, tier: str | None = None,
                as_of: str | None = None, expires_at: str | None = None,
                superseded: int | None = None, recurring: int | None = None,
                codebase_ref: str | None = None,
                created_at: int | None = None,
                unit: Unit | None = None) -> dict[str, Any] | None:
    """Write a memory, and return the identity the database gave it.

    The searchable form of the text is not passed and cannot be: it is a
    generated column, computed by Postgres from the content in this same
    statement. So a memory is findable by word the moment it lands, with no
    second write to forget and no window in which it is stored and
    unsearchable - and nothing above this layer has to know how text search
    is configured.
    """
    values = {
        "mind_id": mind_id,
        "content": content,
        "embedding": None if embedding is None else [float(v)
                                                     for v in embedding],
        "tags": tags,
        "source": source,
        "data_class": data_class,
        "tier": tier,
        "as_of": as_of,
        "expires_at": expires_at,
        "superseded": superseded,
        "recurring": recurring,
        "codebase_ref": codebase_ref,
        "created_at": created_at,
    }
    sql, args = _sql.insert("memories", values, returning=("id",))
    return await _execute_returning(unit, sql, *args)


async def get(memory_id: int, *,
              unit: Unit | None = None) -> dict[str, Any] | None:
    """One memory by its identity."""
    return await _fetch_one(
        unit, f'SELECT {_READ} FROM {qualified("memories")} WHERE "id" = $1',
        memory_id)


async def delete(memory_id: int, *, unit: Unit | None = None) -> dict[str, int]:
    """Remove one memory, reporting whether there was one."""
    return await _execute(
        unit, f'DELETE FROM {qualified("memories")} WHERE "id" = $1',
        memory_id)


async def similar(embedding: Sequence[float], *, limit: int = VECTOR_POOL,
                  mind_id: str | None = None,
                  mind_ids: Sequence[str] | None = None,
                  unit: Unit | None = None) -> list[dict[str, Any]]:
    """The memories nearest a vector, nearest first, with their similarity.

    Cosine, which is the measure lucent scores with, and not Euclidean
    distance: the two agree on a self-match and disagree the moment two
    vectors differ in magnitude rather than direction.

    An exact scan. pgvector's approximate indexes stop at 2000 dimensions
    and these embeddings are 4096, so there is no index to build; measured
    over the live corpus the scan costs 190ms warm, against a statement
    deadline of 30 seconds.
    """
    values = _checked_query_vector(embedding)
    clause, args = _provenance(mind_id, mind_ids, 2)
    conditions = ['"embedding" IS NOT NULL']
    if clause:
        conditions.append(clause)
    sql = (f'SELECT {_READ}, 1 - ("embedding" <=> $1) AS "score" '
           f'FROM {qualified("memories")} '
           f'WHERE {" AND ".join(conditions)} '
           f'ORDER BY "embedding" <=> $1 '
           f'LIMIT {int(limit)}')
    rows = await _fetch(unit, sql, values, *args)
    # A stored vector of all zeros gives NaN rather than a number, and NaN
    # sorts last, so these are only ever at the tail. Dropped rather than
    # returned with an unorderable score, which is what lucent does with a
    # row whose embedding it cannot use.
    return [r for r in rows if not math.isnan(float(r["score"]))]


async def keyword(query: str, *, limit: int = KEYWORD_SCAN,
                  mind_id: str | None = None,
                  mind_ids: Sequence[str] | None = None,
                  unit: Unit | None = None) -> list[dict[str, Any]]:
    """The memories whose text matches a query's words, best match first.

    The score is `ts_rank` multiplied into the range FTS5's BM25 was
    returning, so the figure means what it meant before.
    """
    parsed = _tsquery(query)
    if parsed is None:
        return []
    clause, args = _provenance(mind_id, mind_ids, 2)
    conditions = [f'"content_search" @@ to_tsquery(\'{TEXT_CONFIG}\', $1)']
    if clause:
        conditions.append(clause)
    sql = (f'SELECT {_READ}, '
           f'ts_rank("content_search", to_tsquery(\'{TEXT_CONFIG}\', $1)) '
           f'* {KEYWORD_SCALE} AS "score" '
           f'FROM {qualified("memories")} '
           f'WHERE {" AND ".join(conditions)} '
           f'ORDER BY "score" DESC, "id" ASC '
           f'LIMIT {int(limit)}')
    return await _fetch(unit, sql, parsed, *args)


def _recency(created_at: Any, now: float) -> float:
    """lucent's decay, unchanged: half-life 30 days, never below half."""
    try:
        age = max(0.0, now - float(created_at or 0))
    except (TypeError, ValueError):
        return RECENCY_FLOOR
    raw = math.exp(-age / (RECENCY_HALF_LIFE_DAYS * 86400))
    return max(RECENCY_FLOOR, raw)


async def recall(*, query: str, embedding: Sequence[float],
                 k: int = DEFAULT_K,
                 mind_id: str | None = None,
                 mind_ids: Sequence[str] | None = None,
                 min_score: float | None = None,
                 debug: bool = True,
                 now: float | None = None,
                 unit: Unit | None = None) -> dict[str, Any]:
    """One blended answer: similarity, recency and keywords together.

    lucent's algorithm, carried across step for step. The candidate pool is
    the top `VECTOR_POOL` by cosine unioned with the top `KEYWORD_POOL` by
    keyword rank; the answer is then allocated in fixed slots - three to the
    best `cosine * recency`, one to the best raw cosine regardless of age,
    one to the best keyword hit - and anything left over is filled from a
    combined ranking.

    `now` is a parameter so the decay can be driven from a test without
    waiting thirty days, and defaults to the wall clock.
    """
    k = max(1, min(k, 20))
    moment = time.time() if now is None else now
    values = _checked_query_vector(embedding)

    by_id: dict[int, dict[str, Any]] = {}
    cosine_scores: dict[int, float] = {}
    for row in await similar(values, limit=VECTOR_POOL, mind_id=mind_id,
                             mind_ids=mind_ids, unit=unit):
        row = dict(row)
        cosine_scores[int(row["id"])] = float(row.pop("score"))
        by_id[int(row["id"])] = row

    keyword_scores: dict[int, float] = {}
    for row in await keyword(query, limit=KEYWORD_SCAN, mind_id=mind_id,
                             mind_ids=mind_ids, unit=unit):
        row = dict(row)
        rid = int(row["id"])
        keyword_scores[rid] = float(row.pop("score"))
        if rid not in by_id:
            by_id[rid] = row
            # A keyword hit outside the vector pool still needs a cosine for
            # the slot arithmetic. lucent has one for every row because it
            # scored the whole store; here the pool stopped at twenty, so
            # the rest are scored on their own.
    outside = [rid for rid in keyword_scores if rid not in cosine_scores]
    if outside:
        sql = (f'SELECT "id", 1 - ("embedding" <=> $1) AS "score" '
               f'FROM {qualified("memories")} '
               f'WHERE "id" = ANY($2::bigint[]) AND "embedding" IS NOT NULL')
        for row in await _fetch(unit, sql, values, outside):
            score = float(row["score"])
            if not math.isnan(score):
                cosine_scores[int(row["id"])] = score

    top_keyword = [
        rid for rid, _ in sorted(keyword_scores.items(),
                                 key=lambda kv: kv[1], reverse=True)
    ][:KEYWORD_POOL]
    pool_ids = list(dict.fromkeys(list(cosine_scores)[:VECTOR_POOL]
                                  + top_keyword))

    scored: list[dict[str, Any]] = []
    for rid in pool_ids:
        if rid not in by_id:
            continue
        cos = cosine_scores.get(rid, 0.0)
        rec = _recency(by_id[rid].get("created_at"), moment)
        bm = keyword_scores.get(rid, 0.0)
        # A row that fails the similarity threshold is still kept when the
        # words matched: the threshold is about what the vector could not
        # find, and a keyword hit is evidence the vector missed something.
        if min_score is not None and cos < min_score and bm <= 0:
            continue
        scored.append({"rid": rid, "cos": cos, "rec": rec, "bm": bm,
                       "row": by_id[rid]})

    if not scored:
        return {"memories": [], "count": 0, "mode": "hybrid", "pool_size": 0}

    rec_slots = k
    cos_slots = 1 if k >= 4 else 0
    bm_slots = 1 if k >= 5 else 0
    rec_slots = min(rec_slots, k)
    cos_slots = min(cos_slots, k - rec_slots)
    bm_slots = min(bm_slots, k - rec_slots - cos_slots)

    used: set[int] = set()
    picks: list[tuple[str, dict[str, Any]]] = []

    for entry in sorted(scored, key=lambda s: s["cos"] * s["rec"],
                        reverse=True):
        if len(picks) >= rec_slots:
            break
        used.add(entry["rid"])
        picks.append(("recency", entry))

    taken = 0
    for entry in sorted(scored, key=lambda s: s["cos"], reverse=True):
        if taken >= cos_slots:
            break
        if entry["rid"] in used:
            continue
        used.add(entry["rid"])
        picks.append(("cosine", entry))
        taken += 1

    taken = 0
    for entry in sorted(scored, key=lambda s: s["bm"], reverse=True):
        if taken >= bm_slots or entry["bm"] <= 0:
            break
        if entry["rid"] in used:
            continue
        used.add(entry["rid"])
        picks.append(("bm25", entry))
        taken += 1

    if len(picks) < k:
        combined = sorted(
            scored,
            key=lambda s: (s["cos"] * s["rec"]) + (0.05 * s["bm"]),
            reverse=True)
        for entry in combined:
            if len(picks) >= k:
                break
            if entry["rid"] in used:
                continue
            used.add(entry["rid"])
            picks.append(("fill", entry))

    out = []
    for bucket, entry in picks:
        row = dict(entry["row"])
        if debug:
            row["debug"] = {
                "bucket": bucket,
                "cosine": round(entry["cos"], 4),
                "recency_mult": round(entry["rec"], 4),
                "combined": round(entry["cos"] * entry["rec"], 4),
                "bm25": round(entry["bm"], 4),
            }
        row["score"] = round(entry["cos"], 4)
        out.append(row)

    return {"memories": out, "count": len(out), "mode": "hybrid",
            "pool_size": len(pool_ids)}
