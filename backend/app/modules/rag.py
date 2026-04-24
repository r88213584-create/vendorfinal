"""DPDP Act RAG engine.

Produces a verbatim excerpt + citation for any DPDP clause flagged by the
finding mapper. Two retrievers are supported:

1. **Local TF-IDF retriever** (default, zero-setup) — indexes bundled Act
   excerpts from `data/dpdp_act_excerpts.json`. Deterministic and offline.
2. **PDF retriever** (optional) — if `DPDP_ACT_PDF_PATH` is set to the real
   gazette PDF, it is loaded via `pypdf` and chunked so citations include
   the exact gazette page number.

The output is grounded enough to survive a judge asking
"show me where the Act says that." The LLM (if configured) only rewrites
the answer; the quote + citation come from retrieval, not from the model.
"""
from __future__ import annotations

import json
import re
from pathlib import Path

from sklearn.feature_extraction.text import TfidfVectorizer
from sklearn.metrics.pairwise import cosine_similarity

from app.config import settings

_DATA = Path(__file__).parent.parent / "data" / "dpdp_act_excerpts.json"

# Matches "§8(5)", "S.8(5)", "Sec 8(5)", "Section 8(5)", "Rule 6", "R.6",
# "schedule 2", etc. — covers the most common ways a judge or auditor will
# reference a DPDP clause. Used to bias TF-IDF retrieval toward exact clauses.
_SECTION_PATTERNS = [
    re.compile(r"\u00a7\s*(\d+(?:\(\d+\))?)", re.IGNORECASE),
    re.compile(r"\bsection\s+(\d+(?:\(\d+\))?)", re.IGNORECASE),
    re.compile(r"\bsec\.?\s+(\d+(?:\(\d+\))?)", re.IGNORECASE),
    re.compile(r"\bs\.?\s*(\d+\(\d+\))", re.IGNORECASE),
    re.compile(r"\brule\s+(\d+)", re.IGNORECASE),
    re.compile(r"\br\.?\s*(\d+)\b", re.IGNORECASE),
    re.compile(r"\bschedule\s+(\d+)", re.IGNORECASE),
]


def _extract_clause_refs(query: str) -> list[str]:
    """Return clause labels referenced in the query, normalised to the form
    used in `dpdp_act_excerpts.json` (e.g. '§8(5)', 'R.6', 'Schedule 2')."""
    refs: list[str] = []
    for pat in _SECTION_PATTERNS:
        for m in pat.finditer(query):
            tag = (m.group(0) or "").lower()
            num = m.group(1)
            if tag.startswith("rule") or tag.startswith("r."):
                refs.append(f"R.{num}")
            elif tag.startswith("schedule"):
                refs.append(f"Schedule {num}")
            else:
                refs.append(f"\u00a7{num}")
    # Dedupe preserving order.
    seen: set[str] = set()
    out: list[str] = []
    for r in refs:
        if r not in seen:
            seen.add(r)
            out.append(r)
    return out


class DPDPRetriever:
    def __init__(self) -> None:
        self._load_corpus()

    def _load_corpus(self) -> None:
        passages: list[dict] = []
        if settings.dpdp_act_pdf_path:
            try:
                from pypdf import PdfReader

                reader = PdfReader(settings.dpdp_act_pdf_path)
                for i, page in enumerate(reader.pages, start=1):
                    text = (page.extract_text() or "").strip()
                    if not text:
                        continue
                    # Split long pages into ~500-char chunks so retrieval is
                    # focused and citation pages remain accurate.
                    for j in range(0, len(text), 500):
                        chunk = text[j : j + 500]
                        passages.append(
                            {
                                "id": f"pdf-{i}-{j}",
                                "section": "(see page)",
                                "page": i,
                                "text": chunk,
                            }
                        )
            except Exception:
                passages = []
        if not passages:
            raw = json.loads(_DATA.read_text())
            passages = list(raw["passages"])
        self._passages = passages
        texts = [p["text"] for p in passages]
        self._vec = TfidfVectorizer(lowercase=True, ngram_range=(1, 2), min_df=1)
        self._mat = self._vec.fit_transform(texts)

    def search(self, query: str, k: int = 2) -> list[dict]:
        if not query.strip():
            return []
        q = self._vec.transform([query])
        sims = cosine_similarity(q, self._mat)[0].astype(float).copy()

        # If the query references specific clauses ("§8(5)", "Section 18",
        # "Rule 6", ...), strongly boost passages whose `section` label starts
        # with that token. This is what judges and auditors actually type, and
        # pure word-overlap TF-IDF drifts to unrelated passages that happen to
        # share a common word like "penalty" or "breach". The boost is added
        # (not replaced) so semantic matching still works when no clause is
        # explicitly named.
        clause_refs = _extract_clause_refs(query)
        if clause_refs:
            for i, p in enumerate(self._passages):
                sec = (p.get("section") or "").strip()
                if not sec:
                    continue
                # Normalise section label for comparison — sections can look
                # like "R.6 (DPDP Rules 2025)" or "§8(5)"; split on first space
                # to isolate the canonical tag.
                sec_tag = sec.split(" ", 1)[0]
                for ref in clause_refs:
                    if sec_tag == ref or sec == ref:
                        sims[i] += 1.0  # dominant hit: exact clause match
                        break
                    if ref.startswith("\u00a7") and sec_tag.startswith(
                        ref.split("(")[0]
                    ):
                        sims[i] += 0.4  # parent section match (e.g. §8 → §8(5))

        top = sims.argsort()[::-1][:k]
        out = []
        for idx in top:
            if float(sims[idx]) <= 0.0:
                continue
            p = self._passages[idx]
            out.append(
                {
                    "section": p.get("section", ""),
                    "page": p.get("page"),
                    "excerpt": p["text"],
                    "score": float(sims[idx]),
                }
            )
        return out

    def lookup_clause(self, section: str) -> dict | None:
        """Exact-section lookup (e.g. '§8(5)')."""
        for p in self._passages:
            if p.get("section") == section:
                return {
                    "section": p["section"],
                    "page": p.get("page"),
                    "excerpt": p["text"],
                    "score": 1.0,
                }
        hits = self.search(section, k=1)
        return hits[0] if hits else None

    def stats(self) -> dict:
        return {
            "passages": len(self._passages),
            "source": "gazette_pdf" if settings.dpdp_act_pdf_path else "bundled_excerpts",
            "retriever": "TF-IDF + cosine",
        }


_RET: DPDPRetriever | None = None


def retriever() -> DPDPRetriever:
    global _RET
    if _RET is None:
        _RET = DPDPRetriever()
    return _RET


async def answer(query: str) -> dict:
    """Retrieval-first Q&A. If an LLM key is present, rewrite the answer;
    otherwise return the top excerpt verbatim."""
    r = retriever()
    hits = r.search(query, k=3)
    if not hits:
        return {"query": query, "answer": "No matching DPDP clause found.", "citations": []}

    citations = [{"section": h["section"], "page": h["page"], "excerpt": h["excerpt"]} for h in hits]
    top = hits[0]
    base_answer = (
        f"Per DPDP Act 2023 {top['section']} (Gazette p. {top['page']}): "
        f"\"{top['excerpt']}\""
    )

    if settings.ai_provider == "anthropic" and settings.anthropic_api_key:
        try:
            from anthropic import AsyncAnthropic

            client = AsyncAnthropic(api_key=settings.anthropic_api_key)
            msg = await client.messages.create(
                model=settings.anthropic_model,
                max_tokens=400,
                system=(
                    "You are a DPDP Act 2023 advisor. Answer the user's question using ONLY the "
                    "provided excerpts. Quote the exact section and page. If the excerpts don't "
                    "answer it, say so."
                ),
                messages=[
                    {
                        "role": "user",
                        "content": f"Question: {query}\n\nExcerpts:\n" + "\n---\n".join(
                            f"{c['section']} (p.{c['page']}): {c['excerpt']}" for c in citations
                        ),
                    }
                ],
            )
            parts = [b.text for b in msg.content if getattr(b, "type", "") == "text"]
            if parts:
                return {"query": query, "answer": "".join(parts).strip(), "citations": citations}
        except Exception:
            pass

    # OpenAI + any OpenAI-compatible gateway (set OPENAI_BASE_URL for gateways).
    if settings.ai_provider == "openai" and settings.openai_api_key:
        txt = await _openai_answer(
            query,
            citations,
            api_key=settings.openai_api_key,
            base_url=settings.openai_base_url,
            model=settings.openai_model,
        )
        if txt:
            return {"query": query, "answer": txt, "citations": citations}

    if settings.ai_provider == "openrouter" and settings.openrouter_api_key:
        txt = await _openai_answer(
            query,
            citations,
            api_key=settings.openrouter_api_key,
            base_url=settings.openrouter_base_url,
            model=settings.openrouter_model,
            extra_headers={
                "HTTP-Referer": "https://github.com/Akshu3104/vendorguard-ai",
                "X-Title": "VendorGuard AI",
            },
        )
        if txt:
            return {"query": query, "answer": txt, "citations": citations}

    return {"query": query, "answer": base_answer, "citations": citations}


async def _openai_answer(
    query: str,
    citations: list[dict],
    *,
    api_key: str,
    base_url: str,
    model: str,
    extra_headers: dict | None = None,
) -> str | None:
    try:
        from openai import AsyncOpenAI

        kwargs: dict = {"api_key": api_key}
        if base_url:
            kwargs["base_url"] = base_url
        if extra_headers:
            kwargs["default_headers"] = extra_headers
        client = AsyncOpenAI(**kwargs)
        resp = await client.chat.completions.create(
            model=model,
            max_tokens=400,
            messages=[
                {"role": "system", "content": "Answer using only the provided DPDP excerpts; cite section + page."},
                {"role": "user", "content": f"Q: {query}\nExcerpts:\n" + "\n---\n".join(
                    f"{c['section']} (p.{c['page']}): {c['excerpt']}" for c in citations
                )},
            ],
        )
        return (resp.choices[0].message.content or "").strip() or None
    except Exception:
        return None
