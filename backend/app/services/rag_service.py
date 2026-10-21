"""Orchestration for the profile assistant.

This module used to be ~1,200 lines and did everything: seven keyword predicates
with ~400 lines of Spanish substring lists, query expansion, retrieval, prompt
construction with the facts baked in, generation, and streaming. It is now the
thin layer that owns the `ChatResponse` contract and the SSE wire format, so
`api/chat.py` and the frontend are unaffected by the rewrite underneath.

Retrieval lives in `retrieval.py`, the tool loop in `agent.py`, and the
fabricated-entity check in `grounding.py`.

What is deliberately kept: the pre-LLM safety filter, the `OUT_OF_SCOPE`
contract that drives `needs_contact_form`, the contact fast-path, and the
language detection that lets a Spanish visitor get a Spanish answer from an
English corpus.
"""

from __future__ import annotations

import json
import logging
import re
from collections.abc import Generator
from datetime import datetime, timezone
from functools import lru_cache
from pathlib import Path

import numpy as np
from openai import OpenAI

from app.config import settings
from app.models import ChatResponse, Citation
from app.services.agent import AgentLimits, AgentResult, ProfileAgent
from app.services.retrieval import RetrievalIndex

logger = logging.getLogger(__name__)


class AgenticRAGService:
    """Shared index across requests; one agent per request."""

    _index: RetrievalIndex | None = None

    def __init__(self) -> None:
        self._client = self._build_client()
        self._model = settings.openai_model
        self._embedder_service = None
        # The suggested prompts are the most asked questions and the prefetch
        # embeds the question verbatim, so the same text recurs: a hit saves a
        # 0.4-0.7 s Gemini round trip. lru_cache does not store exceptions, so a
        # failed call is retried next time instead of pinning the query to BM25.
        self._embed_cached = lru_cache(maxsize=128)(self._embed_uncached)

    # --- startup ------------------------------------------------------------

    @classmethod
    def initialize_cache(
        cls,
        cache_path: str | None = None,
        vocabulary_path: str | None = None,
    ) -> None:
        """Load the index at application startup (FastAPI lifespan).

        Falls back to the previous cache if the primary one is missing or
        unreadable, so publishing a bad index degrades retrieval rather than
        taking the service offline.
        """
        primary = Path(cache_path or settings.embeddings_cache_path)

        vocabulary = Path(vocabulary_path or settings.vocabulary_path)
        if not vocabulary.exists() and not vocabulary_path:
            # Container layout puts it beside the app; a checkout puts it under
            # data/kb/. Try both rather than silently losing grounding.
            fallback = Path(settings.vocabulary_path_fallback)
            if fallback.exists():
                vocabulary = fallback

        index = RetrievalIndex.load(primary, vocabulary)
        if index.is_empty:
            fallback = Path(settings.embeddings_cache_fallback)
            if fallback.exists():
                logger.warning("Primary index unusable; falling back to %s", fallback)
                index = RetrievalIndex.load(fallback, vocabulary)

        cls._index = index
        if index.is_empty:
            logger.error("Index is empty — the assistant cannot ground its answers")
        else:
            logger.info(
                "Index ready: %d documents, %d vocabulary terms, embedding model=%s",
                len(index),
                len(index.vocabulary),
                index.model,
            )

    @classmethod
    def _get_index(cls) -> RetrievalIndex:
        if cls._index is None:
            cls.initialize_cache()
        return cls._index  # type: ignore[return-value]

    # --- clients ------------------------------------------------------------

    @staticmethod
    def _build_client() -> OpenAI | None:
        """Direct OpenAI only.

        The AzureOpenAI branch that used to be here was unreachable — the API key
        took precedence — and pointed at a resource that no longer exists in the
        subscription.
        """
        if settings.openai_api_key:
            return OpenAI(api_key=settings.openai_api_key)
        logger.error("OPENAI_API_KEY is not set; the assistant cannot generate answers")
        return None

    def _embed_query(self, text: str) -> np.ndarray | None:
        """Embed a query, returning None so retrieval degrades to BM25 on failure."""
        if not settings.google_api_key:
            return None
        try:
            return self._embed_cached(text)
        except Exception as exc:
            logger.warning("Query embedding failed (%s); falling back to keyword search", exc)
            return None

    def _embed_uncached(self, text: str) -> np.ndarray:
        if self._embedder_service is None:
            from app.services.embedding_service import EmbeddingService

            self._embedder_service = EmbeddingService(
                settings.google_api_key, settings.embedding_model
            )
        vector = np.asarray(self._embedder_service.embed_query(text), dtype=np.float32)
        vector.setflags(write=False)  # shared by every hit on the cache
        return vector

    def _build_agent(self) -> ProfileAgent:
        return ProfileAgent(
            client=self._client,
            model=self._model,
            index=self._get_index(),
            embedder=self._embed_query,
            limits=AgentLimits(
                max_iterations=settings.agent_max_iterations,
                max_tool_calls=settings.agent_max_tool_calls,
                search_top_k=settings.retrieval_top_k,
            ),
            reasoning_effort=settings.openai_reasoning_effort,
        )

    # --- public API ---------------------------------------------------------

    def ask(
        self,
        question: str,
        top_k: int = 6,
        history: list[dict] | None = None,
        current_time: datetime | None = None,
        language: str | None = None,
    ) -> ChatResponse:
        history = history or []
        now = current_time or datetime.now(timezone.utc)
        language = resolve_language(question, history, language)
        logger.info("[ASK] q=%r lang=%s turns=%d", question[:120], language, len(history))

        fast_path = self._fast_path(question, language)
        if fast_path is not None:
            return fast_path

        if self._client is None:
            return self._response(self._unavailable_message(language), [], needs_contact=False)

        result = self._build_agent().answer(question, history, language, now)
        if result.out_of_scope:
            logger.info("[ASK] out_of_scope")
            return self._response(
                out_of_scope_message(result.language or language), [], needs_contact=True
            )

        logger.info(
            "[ASK] documents=%s regenerated=%s",
            [d.id for d in result.documents],
            result.regenerated,
        )
        return self._response(result.answer, result.documents, needs_contact=False)

    def ask_stream(
        self,
        question: str,
        top_k: int = 6,
        history: list[dict] | None = None,
        current_time: datetime | None = None,
        language: str | None = None,
    ) -> Generator[str, None, None]:
        """Yield SSE frames. The wire format is what Chat.jsx parses; do not change it."""
        history = history or []
        now = current_time or datetime.now(timezone.utc)
        language = resolve_language(question, history, language)
        # This log lives in `ask` too. Without it here the streaming path — the
        # one the site actually uses — was undiagnosable: production had 35 chat
        # requests and not one line saying which language was picked.
        logger.info("[STREAM] q=%r lang=%s turns=%d", question[:120], language, len(history))

        fast_path = self._fast_path(question, language)
        if fast_path is not None:
            yield _sse_token(fast_path.answer)
            yield _sse_done(fast_path.needs_contact_form)
            return

        if self._client is None:
            yield _sse_token(self._unavailable_message(language))
            yield _sse_done(False)
            return

        sent = False
        result = None
        try:
            for item in self._build_agent().answer_stream(question, history, language, now):
                if isinstance(item, AgentResult):
                    result = item
                else:
                    sent = True
                    yield _sse_token(item)
        except Exception as exc:
            logger.error("[STREAM] agent failed: %s", exc, exc_info=True)
            # Text already on screen stays; only an empty bubble gets the apology.
            if not sent:
                yield _sse_token(self._unavailable_message(language))
            yield _sse_done(False)
            return

        if result is not None and result.out_of_scope:
            yield _sse_token(out_of_scope_message(result.language or language))
            yield _sse_done(True)
            return

        logger.info("[STREAM] documents=%s", [d.id for d in result.documents] if result else [])
        yield _sse_done(False)

    # --- fast paths ---------------------------------------------------------

    def _fast_path(self, question: str, language: str) -> ChatResponse | None:
        """Answers that need no model call, and the one safety filter kept pre-LLM."""
        if is_greeting(question):
            return self._response(greeting_message(language), [], needs_contact=False)
        if is_contact_request(question):
            return self._response(self._contact_message(language), [], needs_contact=False)
        if is_inappropriate(question):
            logger.info("[FILTER] inappropriate q=%r", question[:120])
            return self._response(out_of_scope_message(language), [], needs_contact=True)
        return None

    # --- response assembly --------------------------------------------------

    def _response(self, answer: str, documents, needs_contact: bool) -> ChatResponse:
        citations = (
            [Citation(source=d.id, chunk=d.text) for d in documents]
            if settings.show_citations
            else []
        )
        return ChatResponse(
            answer=answer,
            used_retrieval=bool(documents),
            citations=citations,
            needs_contact_form=needs_contact,
            contact_emails=contact_emails(),
            contact_linkedin=settings.professional_linkedin or None,
        )

    def _contact_message(self, language: str) -> str:
        lines = (
            ["You can reach Domingo Berbel through these professional channels:"]
            if language == "en"
            else ["Puedes contactar con Domingo Berbel por estos canales profesionales:"]
        )
        linkedin = (settings.professional_linkedin or "").strip()
        if linkedin:
            lines.append(f"- LinkedIn: {linkedin}")
        emails = contact_emails()
        if emails:
            lines.append("- Email: " + " / ".join(emails))
        return "\n".join(lines)

    @staticmethod
    def _unavailable_message(language: str) -> str:
        return (
            "The assistant is temporarily unavailable. Please try again in a moment."
            if language == "en"
            else "El asistente no está disponible temporalmente. Inténtalo de nuevo en un momento."
        )


# ── SSE helpers ─────────────────────────────────────────────────────────────


def _sse_token(text: str) -> str:
    return f"data: {json.dumps({'token': text})}\n\n"


def _sse_done(needs_contact: bool) -> str:
    payload = {
        "done": True,
        "needs_contact_form": needs_contact,
        "contact_emails": contact_emails(),
        "contact_linkedin": settings.professional_linkedin or None,
    }
    return f"data: {json.dumps(payload)}\n\n"


# ── module-level helpers (pure, so they are testable) ───────────────────────


def contact_emails() -> list[str]:
    return [x.strip() for x in settings.contact_emails.split(",") if x.strip()]


def out_of_scope_message(language: str = "es") -> str:
    emails = contact_emails()
    contact = " / ".join(emails) if emails else ""
    linkedin = (settings.professional_linkedin or "").strip()
    if language == "en":
        text = "I can only answer questions about Domingo Berbel's professional background."
        if contact:
            text += f" For anything else, you can contact him at: {contact}."
    else:
        text = "Solo puedo responder sobre la trayectoria profesional de Domingo Berbel."
        if contact:
            text += f" Para otros temas, puedes contactar con él en: {contact}."
    if linkedin:
        text += f" LinkedIn: {linkedin}"
    return text


def greeting_message(language: str = "es") -> str:
    if language == "en":
        return (
            "Hi, I'm Domingo Berbel's assistant. Ask me about his experience, projects, "
            "education or how he might fit a role."
        )
    return (
        "Hola, soy el asistente de Domingo Berbel. Pregúntame por su experiencia, proyectos, "
        "formación o su encaje en un puesto."
    )


_GREETINGS = frozenset(
    {"hola", "buenas", "buenas tardes", "buenos dias", "buenos días", "buenas noches",
     "hello", "hi", "hey", "good morning", "good afternoon", "good evening"}
)


def is_greeting(question: str) -> bool:
    return question.strip().lower().rstrip("!.?¿¡,") in _GREETINGS


_CONTACT_PATTERNS = (
    "cómo contacto", "como contacto", "cómo puedo contactar", "como puedo contactar",
    "cómo le contacto", "como le contacto", "dónde contactar", "donde contactar",
    "información de contacto", "datos de contacto", "cómo me pongo en contacto",
    "como me pongo en contacto", "how to contact", "how can i contact",
    "how do i contact", "contact information", "contact details", "get in touch",
    "email de domingo", "correo de domingo", "linkedin de domingo",
)


def is_contact_request(question: str) -> bool:
    """Only short, explicit requests. A long recruiter pitch should reach the model
    so it can sell the profile rather than just returning an address."""
    if len(question.strip()) > 120:
        return False
    q = question.lower()
    return any(p in q for p in _CONTACT_PATTERNS)


# The one keyword list that survives, because it is a safety filter that must run
# before any model call rather than a routing heuristic.
_INAPPROPRIATE = (
    "gustan los hombre", "gustan los mujer", "gustan las mujer", "gustan las chica",
    "gustan los chico", "es gay", "es homosexual", "es hetero", "orientaci",
    "novia", "novio", "pareja", "casado", "soltero", "sexual", "follar", "sexo",
    "polla", "culo", "tetas", "pene", "vagina", "mierda", "puta", "hijo de",
    "gilipollas", "subnormal", "idiota", "imbecil", "imbécil", "maric", "bollera",
    "travesti", "transexual", "gordo", "feo", "guapo", "atractivo", "droga",
    "borracho", "racis", "suicid",
)


def is_inappropriate(question: str) -> bool:
    q = question.lower().strip()
    return any(p in q for p in _INAPPROPRIATE)


# Function words, not topic words. A closed list of topic words ("experience",
# "projects") only recognises the questions we thought of; function words are the
# part of a sentence a writer cannot avoid, whatever they are asking about.
#
# Any token that exists in both languages is removed from both below: leaving it
# in makes it cancel out on one side while inflating the other, which is how the
# previous version scored "me" and "a" as Spanish evidence in English sentences.
_EN_RAW = frozenset({
    "a", "an", "the", "is", "are", "was", "were", "be", "been", "am",
    "do", "does", "did", "can", "could", "would", "should", "will", "shall",
    "has", "have", "had", "he", "his", "him", "she", "her", "they", "them",
    "you", "your", "yours", "me", "my", "i", "we", "our", "it", "its",
    "of", "in", "on", "at", "to", "for", "with", "from", "about", "into",
    "and", "or", "but", "if", "than", "then", "there", "here",
    "what", "which", "who", "whom", "whose", "where", "when", "why", "how",
    "tell", "give", "show", "list", "any", "some", "more", "most", "much",
    "many", "best", "also", "please", "not", "no", "yes", "so", "as", "that",
    "this", "these", "those", "over", "under", "between", "during", "before",
    "after", "again", "still", "just", "only", "very", "really",
    # Recruiter nouns. One-word questions are common ("Salary?", "certs",
    # "Strengths?") and carry no function word at all; the Spanish list below
    # has always had its counterparts.
    "salary", "skills", "strengths", "weaknesses", "certs", "experience",
    "background", "career", "company", "role", "job", "hire", "hiring", "team",
    "remote", "available", "availability", "notice", "relocate", "summary",
    "resume", "degree", "education", "projects", "achievements", "languages",
    "strong", "weak", "work", "works", "worked", "studied", "speak", "speaks",
    "know", "knows", "use", "used", "uses", "start", "join",
})
_ES_RAW = frozenset({
    "el", "la", "los", "las", "un", "una", "unos", "unas", "lo", "al", "del",
    "de", "en", "con", "por", "para", "sin", "sobre", "entre", "hasta", "desde",
    "que", "qué", "quien", "quién", "cual", "cuál", "cuando", "cuándo",
    "donde", "dónde", "como", "cómo", "cuanto", "cuánto", "cuantos", "cuántos",
    "es", "son", "esta", "está", "estan", "están", "ser", "estar", "fue",
    "tiene", "tienen", "tuvo", "hay", "ha", "han", "hizo", "hace",
    "su", "sus", "mi", "mis", "tu", "tus", "nos", "me", "te", "se", "le", "les",
    "y", "o", "pero", "si", "no", "muy", "más", "menos", "también", "ademas",
    "además", "trabaja", "trabajo", "estudia", "estudio", "habla", "sabe",
    "dame", "cuentame", "cuéntame", "explica", "dime", "resumen",
    "experiencia", "proyectos", "formacion", "formación", "trayectoria",
    "actualmente", "idiomas", "empresa", "puesto", "perfil", "titulacion",
    "titulación", "estudios", "conocimientos", "habilidades",
    "salario", "sueldo", "fortalezas", "debilidades", "fuertes", "débiles",
    "remoto", "disponibilidad", "contratar", "contratarle", "equipo", "logros",
    "certificados", "carrera", "idioma", "trabajó", "estudió", "hizo",
    "conoce", "domina", "maneja", "usa", "utiliza", "puede", "podría", "ya",
    "incorporarse", "incorporación",
})

# A token that means something in both languages is evidence for neither.
_AMBIGUOUS = _EN_RAW & _ES_RAW
_ENGLISH_MARKERS = _EN_RAW - _AMBIGUOUS
_SPANISH_MARKERS = _ES_RAW - _AMBIGUOUS

# Morphology generalises where word lists do not: "certifications",
# "expectations" and "qualifications" are recruiter vocabulary we never listed,
# but the -tions ending is unmistakably English. Matched with endswith, so the
# Spanish "-mente" does not register as the English "-ment".
_EN_SUFFIXES = ("tion", "tions", "ment", "ments", "ness", "ship", "ing", "ly", "ies")
_ES_SUFFIXES = ("ción", "ciones", "miento", "mientos", "mente", "ando", "endo",
                "idad", "idades", "ancia", "encia")

_ACCENTS = "áéíóúñü"
_INVERTED = "¿¡"

SUPPORTED_LANGUAGES = frozenset({"en", "es"})
DEFAULT_LANGUAGE = "es"


def _score(text: str) -> tuple[int, int]:
    """Evidence for English and for Spanish, independently counted."""
    lowered = text.lower()
    tokens = re.findall(r"[a-z" + _ACCENTS + r"]+", lowered)

    english = sum(1 for t in tokens if t in _ENGLISH_MARKERS)
    spanish = sum(1 for t in tokens if t in _SPANISH_MARKERS)

    english += sum(1 for t in tokens if len(t) > 4 and t.endswith(_EN_SUFFIXES))
    spanish += sum(1 for t in tokens if len(t) > 4 and t.endswith(_ES_SUFFIXES))

    # Accents are evidence, never a verdict. Domingo worked in Almería and
    # studied in España; an English question naming those places is still
    # English, and the old code answered every one of them in Spanish.
    if any(ch in lowered for ch in _ACCENTS):
        spanish += 1

    return english, spanish


def _verdict(text: str) -> str | None:
    """The language this text argues for, or None when it argues for neither."""
    if any(ch in text for ch in _INVERTED):
        return "es"  # No English keyboard produces ¿ or ¡ by accident.
    english, spanish = _score(text)
    if english == spanish:
        return None
    return "en" if english > spanish else "es"


def _written_language(question: str, history: list[dict] | None) -> str | None:
    """The language the visitor is writing in, or None when nothing says.

    The corpus is English; the assistant answers in whatever the visitor used, so
    a Spanish recruiter is not forced into English.
    """
    verdict = _verdict((question or "").strip())
    if verdict is not None:
        return verdict

    # The question carries no signal of its own ("Certifications?"). Stay in the
    # language the conversation is already being held in, rather than flipping
    # mid-thread, which is what visitors actually complained about.
    for message in reversed(history or []):
        if message.get("role") != "user":
            continue
        prior = _verdict((message.get("content") or "").strip())
        if prior is not None:
            return prior

    return None


def detect_language(question: str, history: list[dict] | None = None) -> str:
    """Infer the answer language from what the visitor wrote alone."""
    return _written_language(question, history) or DEFAULT_LANGUAGE


def resolve_language(
    question: str,
    history: list[dict] | None = None,
    requested: str | None = None,
) -> str:
    """The language the question is written in beats the site's switch.

    It used to be the other way round, and a visitor on the Spanish site who
    asked in English got a Spanish answer every time. The switch is what the
    visitor reads the site in; the question is what they want to talk in.

    Order: the question's own verdict, then the conversation so far, then the
    switch, then the default. The result is given to the model as an order, so
    one-word recruiter questions ("Salary?", "certs") must be recognised here —
    hence the recruiter nouns in the marker lists. `requested` is client-supplied,
    so anything that is not a language we actually serve is discarded rather
    than trusted.
    """
    written = _written_language(question, history)
    if written is not None:
        return written
    if isinstance(requested, str):
        candidate = requested.strip().lower()
        if candidate in SUPPORTED_LANGUAGES:
            return candidate
    return DEFAULT_LANGUAGE
