"""Model-independent MCP interface for Graph-MIND development memory."""
from __future__ import annotations

from datetime import datetime, timedelta
from pathlib import Path
from typing import Annotated, Any, Literal
import json
import os
import re
import sys
import threading
import uuid

from pydantic import Field

from graph_mind import __version__
from graph_mind.associative_memory import AssociativeMemoryIndex
from graph_mind.coding_memory import CodingMemoryStore
from graph_mind.context_packet import build_context_pack, decide_recall
from graph_mind.conversation_memory import ConversationMemoryStore
from graph_mind.local_brain import LocalBrainStore
from graph_mind.paths import default_development_db

if hasattr(sys.stderr, "reconfigure"):
    sys.stderr.reconfigure(encoding="utf-8", errors="backslashreplace")


SERVER_VERSION = __version__
# The embedding model is loaded from the local Hugging Face cache, but the library still asks the
# hub over the network whether a newer revision exists, every time it loads. That made the first
# save of a session take ~95 s and sent requests off the machine for no reason. Once the model is
# on disk, stay offline.
from graph_mind.local_embedder import model_on_disk  # noqa: E402

if model_on_disk():
    os.environ.setdefault("HF_HUB_OFFLINE", "1")
    os.environ.setdefault("TRANSFORMERS_OFFLINE", "1")


_index_lock = threading.Lock()
_index_due = threading.Event()


def index_in_background(database):
    """Refresh the associative index and the vectors without making the caller wait.

    A save is complete the moment its row is written: recall reads the memory table directly.
    Only associative search needs the index and the vectors, so they are brought up to date by one
    background worker; saves that arrive while it runs are folded into its next pass.
    """
    _index_due.set()
    if not _index_lock.acquire(blocking=False):
        return                                  # the running worker will see _index_due

    def work():
        try:
            while _index_due.is_set():
                _index_due.clear()
                try:
                    with AssociativeMemoryIndex(database) as index:
                        index.sync_sources(limit=200)
                    from graph_mind.warmup import warm
                    warm(database, limit=200)
                except Exception:               # never lose a save over an index refresh;
                    pass                        # brain_index reports and repairs the backlog
        finally:
            _index_lock.release()
            if _index_due.is_set():             # a save landed between the last pass and release
                index_in_background(database)

    threading.Thread(target=work, name="graph-mind-index", daemon=True).start()


def wait_for_index(timeout=120.0):
    """Block until background indexing has finished (tests, and shutting down cleanly)."""
    import time
    deadline = time.monotonic() + timeout
    while _index_due.is_set() or _index_lock.locked():
        if time.monotonic() > deadline:
            return False
        time.sleep(0.05)
    return True


def _about(kind, text):
    return Annotated[kind, Field(description=text)]


# What a parameter does where the tool's own text does not say. One line each: every one goes to
# the model with every request, so nothing the description already covers.
SCOPES = _about(list[str] | None, 'Only these scopes, e.g. ["global"] or a project; default all.')
AS_OF = _about(str | None, "ISO time: only what had happened by then (default now).")
CUTOFF = _about(str | None, "ISO time: only what had been saved by then (default as_of).")
OPTIONAL = "Optional; usually left empty."
TITLE = _about(str | None, "Short title; default: the first line of content.")
SOURCE_REF = _about(str, "Where it came from: a file, URL or id.")
SCOPE = _about(str, "global, or a project scope to keep it apart.")
TAGS = _about(list[str] | None, "Free labels to find it by.")
SOURCE_TYPE = _about(str, "Leave as is.")
CLASS = _about(str | None, OPTIONAL)
SCORE = _about(float | None, OPTIONAL)
EXTRA = _about(dict[str, Any] | None, OPTIONAL)
RELATED = _about(list[str] | None, "Ids of memories this one relates to.")
QUERY = _about(str, "The user's request, in their words.")
POLICY = _about(Literal["auto", "always", "never"], "auto skips requests with no sign of the past.")
MAX_CHARS = _about(int, "Size cap of the returned text.")
ITEMS = _about(int, "Most items to return.")
PROJECT_ID = _about(str | None, "A watched project's id; default all.")
FILE = _about(str | None, "Path inside the project, e.g. src/auth.py.")
CHANGE = _about(str | None, "ADDED, MODIFIED or DELETED.")
DIFF = _about(int, "Diff excerpt size per change, 200-20000.")
REFS = _about(list[str] | None, "Links or ids it is based on.")


def _now():
    return datetime.now().isoformat(timespec="microseconds")


def local_time(value):
    """The store keeps naive local times. Models send "2026-10-01T18:25:00+09:00" or just
    "2026-10-01"; both were rejected outright (CLOCK_DOMAIN_MISMATCH, TIMESTAMP_REQUIRED), so the
    memory was lost. Convert to this machine's local clock instead."""
    if not value:
        return None
    text = str(value).strip().replace("Z", "+00:00")
    if "T" not in text:
        text += "T00:00:00"
    moment = datetime.fromisoformat(text)
    if moment.utcoffset() is not None:
        moment = moment.astimezone().replace(tzinfo=None)
    return moment.isoformat(timespec="microseconds")


def configured_db_path():
    """This machine's index. It is never in the shared folder: a SQLite file there would be
    corrupted by the sync client. The shared memory itself is the log (sharing.py)."""
    configured = os.environ.get("GRAPH_MIND_DB")
    return Path(configured).expanduser() if configured else default_development_db()


def shared_sync(database):
    """Pull every device's new log lines into this index before answering. A no-op without a
    shared folder, and cheap when nothing changed (a size check per log file)."""
    from graph_mind.sharing import folder, sync
    try:
        shared = folder()
        return sync(shared, database) if shared else None
    except Exception as error:      # the hub PC is off, or the folder is offline: answer from
        return {"error": type(error).__name__}   # this PC's index; the rest arrives next time


# The calling model already judged that this request may need memory: that is why it called the
# tool. The keyword router second-guessed it and skipped 38 of 120 LongMemEval questions outright
# (product_recall_eval.py: evidence reaching the packet 48.5% -> 66.7% without it), and deciding
# what a question is about is a language judgement this engine leaves to the model anyway.
DEFAULT_CONTEXT_POLICY = "always"
CONTEXT_LIMIT = 30          # brain_context defaults; bench/ measures with these
CONTEXT_CHARS = 15000


# Retrieval over conversation turns, ported from the benchmark pipeline where it was measured:
# the index is the USER's turns cut into 500-character pieces (the same slices, so the measured
# choices carry over), compared by meaning; assistant turns, which an index of user turns cannot
# see, are reached by the existing word search; the two rankings are fused. Each hit goes to the
# model as the matching 500-character piece rather than the whole turn: long assistant turns used
# to fill the 6,000-character packet after four or five items.
PIECE = 500
INLINE_EMBED_LIMIT = 64
MEMORY_WAIT = 10.0         # seconds a memory search with no word match waits for the model
ASSISTANT_TURN_CAP = 3000
WINDOW_SLACK = 7           # days either side of a resolved "around" date
_EMBEDDER = {}
_backfill = threading.Lock()


def embed_in_background(embedder, texts):
    """Embed a backlog once, in one background worker, then persist it."""
    if not _backfill.acquire(blocking=False):
        return                                   # already filling; the next search retries

    def work():
        try:
            for start in range(0, len(texts), 256):
                # skip what the capture service or another app's server embedded meanwhile, and
                # share each batch at once: after a model change all of them start on the same
                embedder.cache.refresh()
                embedder.embed(texts[start:start + 256])
                embedder.flush()
        except Exception:
            pass
        finally:
            _backfill.release()

    threading.Thread(target=work, name="graph-mind-backfill", daemon=True).start()


def memory_meaning(embedder, query, texts):
    """Cosine of the query with each memory, or None when that cannot be had without making
    the question wait (the model still loading, or a backlog to embed: filled in the background,
    word search answers meanwhile). Memories are few next to turns: embedded on first use.
    It runs only when no memory matched by words, so here waiting for the model beats answering
    "nothing saved": OpenCode starts a fresh server per session, and with the 0.5 s turns wait
    four of eight models were told their dog was unknown right after saving it."""
    try:
        import numpy as np
        wait = getattr(embedder, "WAIT_FOR_MODEL", None)
        if wait is not None and not embedder.ready(max(wait, MEMORY_WAIT)):
            return None
        missing = [t for t in texts if embedder._key(t.strip()[:2000]) not in embedder.cache]
        if len(missing) > INLINE_EMBED_LIMIT:
            embed_in_background(embedder, missing)
            return None
        vectors = np.asarray(embedder.embed(texts + [query]), dtype=np.float32)
        norms = np.linalg.norm(vectors, axis=1)
        similar = vectors[:-1] @ vectors[-1] / np.clip(norms[:-1] * norms[-1], 1e-9, None)
        return similar.tolist()
    except Exception:                        # no local model: word search still answers
        return None


def embedder_for(database):
    """One on-device embedder per store, kept loaded for the life of the server."""
    key = str(database)
    if key not in _EMBEDDER:
        from graph_mind.local_embedder import default_embedder
        _EMBEDDER[key] = default_embedder(database)
    return _EMBEDDER[key]


class _Piece:
    __slots__ = ("revision", "turn_id", "start", "user", "scope", "time", "key", "piece")

    def __init__(self, *values):
        for name, value in zip(self.__slots__, values):
            setattr(self, name, value)


class PieceIndex:
    """Every turn's 500-character pieces and their vectors, held in memory for one store and
    topped up with the turns added since the previous question. Rebuilt per question (hashing
    every piece, gathering every vector) it cost 6.3 s a question at 100,000 turns and grew with
    the store. Turns are only ever added or forgotten; a forgotten one triggers a rebuild."""

    def __init__(self):
        self.lock = threading.Lock()
        self.reset()

    def reset(self):
        import numpy as np
        self.last = 0                     # highest turn revision read
        self.turns = 0                    # turns read
        self.pending = []                 # pieces with no vector yet
        self.seen_vectors = -1
        self.turn_ids = []
        self.revisions = np.zeros(0, dtype=np.int64)
        self.starts = np.zeros(0, dtype=np.int64)
        self.user = np.zeros(0, dtype=bool)
        self.scopes = np.zeros(0, dtype=object)
        self.times = np.zeros(0, dtype="U32")
        self.matrix = None
        self.norms = np.zeros(0, dtype=np.float64)

    def sync(self, database, embedder):
        from graph_mind.warmup import turn_pieces
        generation = getattr(embedder.cache, "generation", 0)
        if generation != getattr(self, "generation", generation):
            self.reset()                  # the cache was found wrong and cleared: so are these
        self.generation = generation
        with ConversationMemoryStore(database) as store:
            count = store.db.execute("SELECT COUNT(*) FROM conversation_turns").fetchone()[0]
            new = store.db.execute(
                "SELECT revision,turn_id,role,scope,happened_at,content_redacted "
                "FROM conversation_turns WHERE revision>? ORDER BY revision",
                (self.last,)).fetchall()
            if count != self.turns + len(new):          # something was forgotten
                self.reset()
                new = store.db.execute(
                    "SELECT revision,turn_id,role,scope,happened_at,content_redacted "
                    "FROM conversation_turns ORDER BY revision").fetchall()
        for revision, turn_id, role, scope, happened_at, content in new:
            for start, piece in turn_pieces(content):
                self.pending.append(_Piece(revision, turn_id, start, role == "user", scope,
                                           happened_at, embedder._key(piece.strip()[:2000]),
                                           piece))
        if new:
            self.last = new[-1][0]
            self.turns += len(new)
        self.promote(embedder, force=bool(new))

    def promote(self, embedder, force=False):
        """Move pending pieces whose vectors now exist into the matrix (only when it can have
        changed: new pieces, or more vectors than last time)."""
        import numpy as np
        if not force and len(embedder.cache) == self.seen_vectors:
            return
        self.seen_vectors = len(embedder.cache)
        ready = [entry for entry in self.pending if entry.key in embedder.cache]
        if not ready:
            return
        self.pending = [entry for entry in self.pending if entry.key not in embedder.cache]
        vectors = np.asarray([embedder.cache.get(entry.key) for entry in ready], dtype=np.float32)
        self.matrix = vectors if self.matrix is None else np.concatenate([self.matrix, vectors])
        norms = np.linalg.norm(vectors.astype(np.float64), axis=1)
        self.norms = np.concatenate([self.norms, norms])
        self.turn_ids.extend(entry.turn_id for entry in ready)
        self.revisions = np.concatenate([self.revisions, [e.revision for e in ready]])
        self.starts = np.concatenate([self.starts, [e.start for e in ready]])
        self.user = np.concatenate([self.user, [e.user for e in ready]])
        scopes = np.array([e.scope for e in ready], dtype=object)
        self.scopes = np.concatenate([self.scopes, scopes])
        self.times = np.concatenate([self.times, np.array([e.time for e in ready], dtype="U32")])

    def select(self, *, about_assistant, scopes, since, until):
        import numpy as np
        mask = np.ones(len(self.turn_ids), dtype=bool) if about_assistant else self.user.copy()
        if scopes:
            mask &= np.isin(self.scopes, list(scopes))
        if since:
            mask &= self.times >= since
        if until:
            mask &= self.times < until
        return mask

    @staticmethod
    def wanted(entry, about_assistant, scopes, since, until):
        return ((about_assistant or entry.user) and (not scopes or entry.scope in scopes)
                and (not since or entry.time >= since) and (not until or entry.time < until))


_PIECES = {}


def pieces_for(database):
    return _PIECES.setdefault(str(database), PieceIndex())


def semantic_turns(database, query, *, scopes=None, since=None, until=None, limit=20, embedder,
                   about_assistant=False):
    """Turns ranked by meaning; each carries the 500-character piece that matched.

    Only the user's turns by default: indexing the assistant's long prose too buried the user's
    facts (benchmark: answer sessions in the top 8 went 105 -> 115 of 120 when it was left out).
    When the question is about what the assistant itself said, its turns join the index."""
    import numpy as np
    index = pieces_for(database)
    with index.lock:
        if hasattr(embedder.cache, "refresh"):
            embedder.cache.refresh()    # vectors the capture service embedded since we loaded
        index.sync(database, embedder)
        mask = index.select(about_assistant=about_assistant, scopes=scopes, since=since,
                            until=until)
        waiting = [entry for entry in index.pending
                   if index.wanted(entry, about_assistant, scopes, since, until)]
        if not mask.any() and not waiting:
            return []
        # Never make a question wait for the store to be embedded: a store that has never been
        # searched by meaning holds ~1,500 pieces per thousand turns, minutes on a busy laptop. A
        # few new pieces are embedded inline; a backlog is filled in the background while this
        # question is answered from what is already embedded (word search covers the rest).
        missing = [entry.piece for entry in waiting]
        # Nor wait for the model itself: an app's first question used to sit through the torch
        # import (38.8 s measured). If it is not loaded within WAIT_FOR_MODEL seconds, this
        # question is answered from word search plus what is embedded already.
        asked = embedder._key(query.strip()[:2000]) in embedder.cache
        wait = getattr(embedder, "WAIT_FOR_MODEL", None)
        loading = (wait is not None and (missing or not asked) and not embedder.ready(wait))
        if loading and not asked:
            return []
        if len(missing) > INLINE_EMBED_LIMIT or (loading and missing):
            embed_in_background(embedder, missing)
        elif missing:
            embedder.embed(missing)
            index.promote(embedder, force=True)
            mask = index.select(about_assistant=about_assistant, scopes=scopes, since=since,
                                until=until)
        rows = np.flatnonzero(mask)
        if not len(rows):
            return []
        question = np.asarray(embedder.embed([query])[0], dtype=np.float32)
        # ponytail: a full scan of every piece per query (one matrix product: ~0.1 s at 100,000
        # turns); an approximate-nearest-neighbour index is the upgrade at millions of pieces.
        norms = index.norms[rows] * float(np.linalg.norm(question.astype(np.float64)))
        dots = (index.matrix[rows] @ question).astype(np.float64)
        scores = np.divide(dots, norms, out=np.zeros(len(rows)), where=norms > 0)
        # best piece per turn; ties go to the earlier turn, then the earlier piece, as before
        order = np.lexsort((index.starts[rows], index.revisions[rows], -scores))
        best = {}
        for i in order:
            turn_id = index.turn_ids[rows[i]]
            if turn_id not in best:
                best[turn_id] = (float(scores[i]), int(index.starts[rows[i]]))
                if len(best) == limit:
                    break
    with ConversationMemoryStore(database) as store:
        found = {row["turn_id"]: store._turn(row) for row in store.db.execute(
            "SELECT * FROM conversation_turns WHERE turn_id IN (" + ",".join("?" * len(best)) + ")",
            list(best))}
    hits = []
    for turn_id, (score, start) in best.items():
        turn = found.get(turn_id)
        if turn is None:                  # forgotten between the scan and this read
            continue
        piece = turn["content"][start:start + PIECE]
        hits.append({**turn, "content": piece, "span": [start, start + len(piece)],
                     "full": turn["content"], "similarity": round(score, 4)})
    return hits


def fuse(*rankings, limit):
    """Reciprocal-rank fusion: a turn high in both lists beats one high in only one."""
    scores, keep = {}, {}
    for ranking in rankings:
        for rank, turn in enumerate(ranking):
            scores[turn["turn_id"]] = scores.get(turn["turn_id"], 0.0) + 1.0 / (60 + rank)
            keep.setdefault(turn["turn_id"], turn)       # the first list's version (its excerpt)
    order = sorted(scores, key=scores.get, reverse=True)[:limit]
    return [keep[turn_id] for turn_id in order]


def excerpt(turn):
    """A word-search hit, cut to one piece: the answering sentence sits within the first 500
    characters of every answer-bearing turn in LongMemEval (span_cap_check.py)."""
    if len(turn["content"]) <= PIECE:
        return turn
    return {**turn, "content": turn["content"][:PIECE], "span": [0, PIECE],
            "full": turn["content"]}


def window(around):
    """"2023-05-14" or "2023-05-01..2023-05-31" -> [start, end) padded by WINDOW_SLACK days:
    "two weeks ago" is approximate, and the turn that mentions it is rarely on the exact day."""
    if not around:
        return None
    first, _, last = str(around).partition("..")
    try:
        start = datetime.fromisoformat(local_time(first.strip()))
        end = datetime.fromisoformat(local_time((last or first).strip()))
    except ValueError:      # "last week" sent unresolved: a hint, so ignore it rather than fail
        return None
    return ((start - timedelta(days=WINDOW_SLACK)).isoformat(timespec="microseconds"),
            (end + timedelta(days=WINDOW_SLACK + 1)).isoformat(timespec="microseconds"))


def gather(database, query, *, scopes=None, as_of, knowledge_cutoff=None, limit=8,
           recent=False, since=None, embedder=None, about_assistant=False, around=None,
           until=None):
    """Curated memories and conversation turns for one request, as recall and context share it.
    `until`: the caller asked about a past moment (as_of / knowledge_cutoff); conversation turns
    after it are left out, as curated memories already were."""
    shared_sync(database)
    since = local_time(since) if since else None
    span = window(around)
    with LocalBrainStore(database) as store:
        result = store.recall(query, scopes=scopes, as_of=as_of, knowledge_cutoff=knowledge_cutoff,
                              limit=limit, recent=recent, since=since,
                              meaning=lambda q, texts: memory_meaning(
                                  embedder or embedder_for(database), q, texts))
    with ConversationMemoryStore(database) as conversations:
        if recent:
            names = sorted({name for match in result["matches"] for name in match["named"]})
            if names:      # "what did Kongi do lately": turns about Kongi, newest first
                hits = conversations.search(" ".join(names), scopes=scopes, limit=50,
                                            until=until)["turns"]
                turns = sorted((t for t in hits if not since or t["happened_at"] >= since),
                               key=lambda t: t["happened_at"], reverse=True)[:limit]
            else:          # "what was I doing": simply the latest turns
                turns = conversations.latest(scopes=scopes, since=since, limit=limit,
                                             until=until)["turns"]
        else:
            words = [excerpt(t) for t in conversations.search(
                         query, scopes=scopes, limit=max(limit, 20), until=until)["turns"]
                     if not since or t["happened_at"] >= since]
    if not recent:
        try:
            meaning = semantic_turns(database, query, scopes=scopes, since=since,
                                     until=until, limit=max(limit, 20),
                                     embedder=embedder or embedder_for(database),
                                     about_assistant=about_assistant)
        except Exception:                 # no local model yet: word search still answers
            meaning = []
        rankings = [meaning, words]
        if span:
            # "What did I buy four weeks ago?": the same search inside that window ranks first.
            # A boost, not a filter: a wrong or loose date still leaves the overall ranking in.
            try:
                inside = semantic_turns(database, query, scopes=scopes, since=span[0],
                                        until=min(span[1], until) if until else span[1],
                                        limit=max(limit, 20),
                                        embedder=embedder or embedder_for(database),
                                        about_assistant=about_assistant)
            except Exception:
                inside = []
            rankings = [inside, [t for t in words if span[0] <= t["happened_at"] < span[1]],
                        *rankings]
        turns = fuse(*rankings, limit=limit)
        if about_assistant:
            # "How many mummies were in the one-shot you wrote?" needs the whole answer, not a
            # 500-character piece of it: the assistant's answers run 1,000-4,000 characters and
            # counts and list positions span them. (Users state facts early in a turn; assistants
            # do not.) Their own answers go in whole, up to ASSISTANT_TURN_CAP.
            turns = [{**t, "content": t.get("full", t["content"])[:ASSISTANT_TURN_CAP],
                      "span": [0, min(len(t.get("full", t["content"])), ASSISTANT_TURN_CAP)]}
                     if t["role"] == "assistant" else t for t in turns]
    turns = [{k: v for k, v in t.items() if k != "full"} for t in turns
             if not until or t["happened_at"] <= until]
    result["conversation_turns"] = turns
    if result["status"] == "UNKNOWN" and turns:
        result["status"] = "KNOWN"
        result["reason"] = "CONVERSATION_TURNS_FOUND"
    return result


def capture_warnings() -> list[str]:
    """What the capture service last reported as wrong (a source that stopped yielding turns)."""
    try:
        from graph_mind.automatic_capture import default_service_state_dir
        status = json.loads((default_service_state_dir() / "status.json")
                            .read_text(encoding="utf-8"))
        return list(status.get("warnings") or [])
    except Exception:
        return []


PROACTIVE_NOTE = (
    "Remember proactively. Whenever the user mentions something about their life, work, "
    "plans, preferences, people, places, meals, purchases, health, decisions or events, "
    "call brain_remember right away with their own words, without asking first and "
    "without waiting to be told to remember it. A fact that can change later (where they "
    "live, a pet, a preference) goes with `about` and `attribute`, so the newest value "
    "replaces the old. Saving too much costs nothing; forgetting "
    "is what the user notices. Do it silently: never tell the user that you saved, "
    "stored or noted something, and do not add lines like 'I saved that to memory'. "
    "Mention memory only when the user asks what you remember or whether it was saved. ")
# set by the installer for apps whose transcripts the capture service already saves
CAPTURED_NOTE = (
    "Every turn of this conversation is saved automatically. Do not call brain_remember for "
    "ordinary chat; call it when the user explicitly asks you to remember something or to "
    "record a decision, and when the user states a fact that can change later (where they live "
    "or work, a pet, a preference, a plan): then with `about` and `attribute`, so the newest "
    "value replaces the old. When an answer came from old conversation turns rather than such "
    "a fact, record the fact you learned the same way, dated by `effective_at`. Silently. ")


GUIDE = (
    "Call brain_context first when a request may depend on the user's prior conversations, "
    "facts, preferences, decisions, projects or work, including 'where did we leave off?'. "
    "It skips unrelated requests and returns a bounded evidence packet instead of "
    "replaying full history. Use brain_recall to look memories up directly, or with "
    "`entity` for the history of one thing in order. For code changed in a time range, "
    "project, file or symbol, use code_activity. brain_folder shows or changes where the "
    "memory lives and shares it with the user's other PCs. When the user asks to "
    "delete something from memory, use brain_forget: list first, delete only what the "
    "user picks. For shared project progress ('이거 프로젝트에 올려줘', '어디까지 "
    "했어?', '제안서 띄워봐') use brain_checkpoint; publish only when asked. If a "
    "result carries capture_warnings, tell the user once, plainly: "
    "conversations from that app are no longer being saved. Preserve provenance.")


def instructions(captured: bool) -> str:
    """What every model is told about the memory: also written to a file for apps that do not
    pass a server's instructions on to the model (OpenCode's instructions file)."""
    return (CAPTURED_NOTE if captured else PROACTIVE_NOTE) + GUIDE


def type_name(error) -> str:
    return type(error).__name__


# Characters that end or extend a quoted argument in PowerShell, cmd or a POSIX shell. A command
# the user is told to paste must run exactly what it shows: a path from a chat (or a web page the
# AI read) like  C:\\Memory"; evil; #  ran "evil" once pasted. No real folder or file needs them.
UNSAFE_ARGUMENT = re.compile(r"[\"'`$;&|<>%^!\r\n\x00]")


def folder_commands(path, share_existing, export_to, import_from) -> str:
    """The terminal commands that do what brain_folder will not do for a chat."""
    for value in (path, export_to, import_from):
        if value and UNSAFE_ARGUMENT.search(value):
            raise ValueError("UNSAFE_PATH_CHARACTERS")
    commands = []
    if path or share_existing:
        commands.append("graph-mind folder" + (f' "{path.strip()}"' if path else "")
                        + (" --share-existing" if share_existing else ""))
    if export_to:
        commands.append(f'graph-mind export "{export_to}"')
    if import_from:
        commands.append(f'graph-mind import "{import_from}"')
    return "\n".join(commands)


def build_server(db_path=None, terminal=False):
    """`terminal`: the user typed the request in a terminal (graph-mind folder ...), so
    brain_folder may change where the memory goes. Apps start the server without it."""
    # here, not at the top: the SDK takes 6-10 s to import, and graph_mind.inject (run before
    # every OpenCode message) needs only gather()
    from mcp import types
    from mcp.server import MCPServer
    database = Path(db_path).expanduser() if db_path is not None else configured_db_path()
    server = MCPServer(
        "graph-mind-memory",
        title="Graph-MIND Universal Personal Memory",
        description="User-owned local brain shared across models, sessions and applications.",
        instructions=instructions(bool(os.environ.get("GRAPH_MIND_CAPTURED"))),
        version=SERVER_VERSION,
    )

    @server.tool(
        name="brain_remember",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=False,
            destructiveHint=False,
            idempotentHint=False,
            openWorldHint=False,
        ),
    )
    def brain_remember(content: str, title: TITLE = None, memory_type: str = "fact",
                       source_ref: SOURCE_REF = "conversation", scope: SCOPE = "global",
                       tags: TAGS = None,
                       entities: list[str] | None = None,
                       effective_at: str | None = None,
                       source_type: SOURCE_TYPE = "mcp-client",
                       supersedes_memory_id: str | None = None,
                       memory_id: str | None = None,
                       memory_class: CLASS = None,
                       modality: CLASS = None,
                       retention: CLASS = None,
                       importance: SCORE = None,
                       confidence: SCORE = None,
                       attributes: EXTRA = None,
                       related_memory_ids: RELATED = None,
                       about: str | None = None,
                       attribute: str | None = None) -> dict[str, Any]:
        """Save what the user just told you, in their own words. Call this proactively.

        A fact that can change later (where they live or work, a pet, a preference, a plan, a
        number they track): also pass `about` (who or what, e.g. "Kongi", "me") and `attribute`
        (which property, a short English snake_case name, e.g. "breed", "home_city",
        "favorite_coffee"). A later value with the same `about` and `attribute` replaces this
        one and recall shows both: the value now and what it was before. Use the same
        `attribute` names every time, and never put the value in the name: "last_trip", not
        "last_trip_paris", or the next trip will not replace it.

        Use it the moment the user mentions anything about their life, work, plans, preferences,
        people, places, meals, purchases, health, decisions or events, e.g. "I had kimchi fried
        rice today", "my dog is called Kongi", "we moved the meeting to Tuesday". Do not ask
        whether to save it and do not wait to be told "remember this". Only `content` is
        required: put the user's own sentence there verbatim. Add `entities` (who or what it is
        about) and `effective_at` (when it happened, ISO time) when you know them. If it updates
        something remembered earlier, pass that memory's id as `supersedes_memory_id`.
        Decisions and their reasons are memories too: `memory_type="decision"`, the reason in
        `content`, the project or component in `entities`.

        Save silently. Do not tell the user you saved it ("I've noted that", "저장해 뒀어"); just
        carry on with the conversation. Talk about memory only if the user asks what you remember
        or whether something was saved.
        """
        # Saving is proactive, so a key the user pastes can arrive here too: mask it with the same
        # rules as captured conversations before it reaches the store or the shared log.
        from graph_mind.conversation_memory import CREDENTIAL_NAME, _redact

        def masked(value):          # every text the memory carries, not only content and title
            if isinstance(value, str):
                return _redact(value)[0]
            if isinstance(value, list):
                return [masked(v) for v in value]
            if isinstance(value, dict):     # {"password": "x"}: the name says what the value is
                return {k: "[REDACTED]" if isinstance(v, str) and v and CREDENTIAL_NAME.fullmatch(
                        str(k)) else masked(v) for k, v in value.items()}
            return value
        content = _redact(content)[0]
        title = _redact(title)[0] if title else content.strip().splitlines()[0][:80]
        tags, entities, source_ref, attributes, about, attribute = masked(
            [tags, entities, source_ref, attributes, about, attribute])
        known_at = _now()
        if about and attribute:
            from graph_mind.local_brain import fact_key
            # ponytail: "breed" and "품종" are two facts; names are the model's to keep stable
            attributes = {**(attributes or {}), "fact": fact_key(about, attribute)}
            entities = list(dict.fromkeys([*(entities or []), about]))
        memory = {"memory_id": memory_id or "brain-" + uuid.uuid4().hex,
            "scope": scope, "memory_type": memory_type, "title": title,
            "content": content, "effective_at": local_time(effective_at) or known_at,
            "known_at": known_at, "actor": "assistant", "tags": tags or [],
            "entities": entities or [],
            "provenance": {"source_type": source_type, "source_ref": source_ref},
            "supersedes_memory_id": supersedes_memory_id}
        optional_profile = {"memory_class": memory_class, "modality": modality,
            "retention": retention, "importance": importance, "confidence": confidence,
            "attributes": attributes, "related_memory_ids": related_memory_ids}
        memory.update({key: value for key, value in optional_profile.items()
                       if value is not None})
        shared_sync(database)          # a memory being superseded may come from another PC
        with LocalBrainStore(database) as store:
            result = store.remember(memory)
        from graph_mind.sharing import append, folder
        if result.get("disposition") == "RECORDED":       # not a forgotten one, either
            try:
                shared = folder()
                if shared:
                    append(shared, "memory", memory)    # now every device's index imports it
            except Exception:
                # ponytail: saved on this PC only; brain_folder(share_existing=true) sends it later
                pass
        index_in_background(database)
        return {**result, "scope": scope, "store": str(database), "indexing": "background"}

    @server.tool(
        name="brain_recall",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=True,
            destructiveHint=False,
            idempotentHint=True,
            openWorldHint=False,
        ),
    )
    def brain_recall(query: str = "", entity: str | None = None,
                     scopes: SCOPES = None,
                     as_of: AS_OF = None,
                     knowledge_cutoff: CUTOFF = None,
                     limit: ITEMS = 8, recent: bool = False,
                     since: str | None = None,
                     about_assistant: bool = False,
                     around: str | None = None) -> dict[str, Any]:
        """Raw lookup: the matching memories and turns as structured rows, not a ready context.

        To answer the user's question from their past, use brain_context instead; it returns one
        bounded text packet ready to read. Use brain_recall to inspect or list: the ids and fields
        of what matched (e.g. before brain_forget or `supersedes_memory_id`), one thing's history
        in order, or what the store knows about.

        `entity` answers "what happened to X, in order": every memory about that one thing (the
        auth module, this project, my address), oldest first, with replaced entries marked and the
        current one picked out. Similarity search returns only the nearest one or two of four
        decisions made about one thing in four sessions; this returns all four. With neither
        `query` nor `entity`, it lists what the store knows about, busiest first.

        `recent`, `since`, `about_assistant` and `around` mean the same as in brain_context.
        """
        if entity or not query:
            import sqlite3

            from graph_mind import entity_timeline as timeline_index
            shared_sync(database)              # every device's memories are in this one index
            db = sqlite3.connect(database)
            try:
                if not entity:
                    return {"entities": timeline_index.entities(db, limit=max(limit, 50))}
                rows = timeline_index.timeline(db, entity, limit=max(limit, 50))
            finally:
                db.close()
            current = [r for r in rows if not r["superseded"]]
            return {"entity": entity, "entries": rows, "count": len(rows),
                    "current": current[-1] if current else None}
        return gather(database, query, scopes=scopes, as_of=as_of or _now(),
                      knowledge_cutoff=knowledge_cutoff, limit=limit, recent=recent, since=since,
                      about_assistant=about_assistant, around=around,
                      until=local_time(knowledge_cutoff or as_of))

    @server.tool(
        name="brain_context",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=True,
            destructiveHint=False,
            idempotentHint=True,
            openWorldHint=False,
        ),
    )
    def brain_context(query: QUERY, scopes: SCOPES = None,
                      as_of: AS_OF = None,
                      knowledge_cutoff: CUTOFF = None,
                      policy: POLICY = DEFAULT_CONTEXT_POLICY,
                      max_chars: MAX_CHARS = CONTEXT_CHARS,
                      limit: ITEMS = CONTEXT_LIMIT, recent: bool = False,
                      since: str | None = None,
                      about_assistant: bool = False,
                      around: str | None = None) -> dict[str, Any]:
        """Answer from the user's past: one bounded text packet to read before replying.

        The default memory call: use it whenever a request may depend on earlier conversations,
        facts, preferences, decisions or work. It returns `context`, a size-capped text of the
        relevant memories and conversation turns, each with its date and source. For structured
        rows, ids or one thing's history use brain_recall instead.

        Set `recent=true` whenever the question is about what happened lately or what the user was
        just doing: "what was I working on?", "where did we leave off?", "what did I do
        yesterday?", "최근에", "아까", "어제", "지금 뭐 하고 있었지?". Results then come newest
        first instead of by word overlap; naming something ("what did Kongi do lately") keeps them
        about that. Set `since` (ISO date or time) to drop anything earlier, e.g. "this week".
        Set `about_assistant=true` when the user asks what YOU said earlier: "which restaurant did
        you recommend?", "what were the steps you gave me?", "네가 아까 뭐라고 했지?". Your own
        past answers are then searched by meaning too, not only by their words.
        Set `around` when the question is about WHEN WE TALKED: "what did we discuss last week?",
        "지난달에 얘기한 거" -> resolve it yourself to a date or "start..end" (e.g. "2026-09-23"
        or "2026-09-01..2026-09-30"). Conversations from then rank first; nothing is dropped.
        Do not set it for when something HAPPENED ("the event I went to two weeks ago"): people
        mention events days or weeks before or after, so that date misleads (measured: on dev2
        it pushed the answering turn out in 2 of 11 questions and helped 2).
        """
        route = decide_recall(query, policy)
        if recent and route["mode"] == "SKIP":         # the model said it is about recent events
            route = {**route, "mode": "SEARCH", "reason": "RECENT_REQUESTED"}
        if route["mode"] == "SKIP":
            return {"status": "SKIPPED", "route": route,
                    "scope_completeness": "NOT_APPLICABLE", "char_budget": max_chars,
                    "used_chars": 0, "estimated_tokens": 0, "selected_items": 0,
                    "omitted_items": 0, "ids": [], "context": ""}
        recalled = gather(database, query, scopes=scopes, as_of=as_of or _now(),
                          knowledge_cutoff=knowledge_cutoff, limit=limit, recent=recent,
                          since=since, about_assistant=about_assistant, around=around,
                          until=local_time(knowledge_cutoff or as_of))
        packet = build_context_pack(recalled, max_chars=max_chars,
                                    order="time" if recent else "relevance")
        # `context` already carries each item's kind, date, title, text and source; the item
        # list repeated all of it and was 2/3 of what the model had to read (43K -> 16K chars)
        packet["ids"] = [item["id"] for item in packet.pop("items")]
        packet["route"] = route
        warnings = capture_warnings()
        if warnings:
            packet["capture_warnings"] = warnings
        if route["mode"] == "EXECUTE":
            packet.setdefault("warnings", []).append(
                "STRUCTURED_EXECUTION_REQUIRED_FOR_COMPLETE_SCOPE_CLAIMS")
        return packet

    @server.tool(
        name="brain_folder",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=False,
            destructiveHint=False,
            idempotentHint=True,
            openWorldHint=False,
        ),
    )
    def brain_folder(path: str | None = None, share_existing: bool = False,
                     reindex: bool = False, export_to: str | None = None,
                     import_from: str | None = None) -> dict[str, Any]:
        """Where the user's own personal memory lives, and which of their own PCs share it.

        Not for teams: project brains shared with teammates are brain_checkpoint.

        Anything that changes where the memory goes (`path`, `share_existing`, `export_to`,
        `import_from`) is not done from here: the tool returns `command`, and the user runs it in
        a terminal. A web page or file you read can then never move their memory somewhere else.
        Show the user the command, say what it does, and call this again without arguments after
        they ran it to confirm. Codes and passwords appear only in that terminal.

        Call it with `path` when the user names a folder for their memory, e.g. "use my Google
        Drive's Graph-MIND folder as my brain". A folder that OneDrive, Google Drive or Dropbox
        syncs makes the same memory available on every PC where the user chooses it too; nothing
        else is needed. Without `path` it reports the current folder and the devices writing to it.
        `path="local"` keeps the brain in this PC's own Postgres instead, shared the instant it is
        written (no sync delay).

        Other PCs: when the user asks to let their other PCs use this brain ("다른 PC도 붙게 해줘"),
        call it with `path="share"`. It opens this PC's Postgres to the local network and Tailscale
        (Windows may ask the user to approve a firewall rule once) and returns a
        `connection_code` in the terminal. On the other PC the user runs
        `graph-mind folder <that code>`; it contains the password, so say not to post it anywhere
        public.
        Codes: when the user pastes any Graph-MIND code ("gm1." for their own other PC, "gmt1."
        for a team invite), call this with `path=<the code>`; it does the right thing for either
        (a team invite is joined at once), so never ask the user which kind it is.

        `share_existing=true` sends what this PC remembers and the shared memory lacks (only that:
        it also repairs turns that missed a hub that was down). It uploads
        it to wherever the folder syncs. Set it only when the user has explicitly agreed to that.

        `reindex=true` brings the search index up to date (links new memories, embeds unembedded
        ones). Saving already does this; it is for a large imported backlog.

        Moving a whole memory as one file ("내 기억 파일로 내보내줘", "이 기억 파일 가져와"):
        `export_to=<file path>` writes every memory and conversation turn into that file;
        `import_from=<file path>` adds such a file's contents to this memory, skipping what is
        already here. Only when the user asks. Tell them the file holds their entire memory
        (secrets were masked when saved), so keep it private like a diary.
        """
        if path and path.strip().startswith("gmt1."):        # a team invite, not a brain folder
            return brain_checkpoint(action="join_team", code=path.strip())
        if not terminal and (path or share_existing or export_to or import_from):
            try:
                command = folder_commands(path, share_existing, export_to, import_from)
            except ValueError as error:
                return {"status": "REFUSED", "reason": str(error),
                        "note": "The path holds characters a terminal would treat as commands. "
                                "Ask the user for the folder or file name again."}
            return {"status": "RUN_IN_TERMINAL",
                    "command": command,
                    "note": "For the user's safety this is not done from a chat: show them this "
                            "command to run in a terminal (PowerShell or Terminal). It prints the "
                            "result there."}
        if export_to or import_from:
            from graph_mind.sharing import export_file, import_file
            result = {}
            if export_to:
                result["exported"] = export_file(database, export_to)
            if import_from:
                result["imported"] = import_file(import_from, database)
                index_in_background(database)
            return result
        if reindex:
            from graph_mind.warmup import warm
            with AssociativeMemoryIndex(database) as index:
                synced = index.sync_sources(limit=1000)
            return {"synced": synced, "vectors_warmed": warm(database, limit=1000),
                    "store": str(database)}
        from graph_mind.sharing import (
            device_name,
            devices,
            export_history,
            folder,
            set_folder,
            share,
            sync,
        )
        shared_out = None
        if path == "share":
            shared_out = share()
        elif path:
            set_folder(path)
        shared = folder()
        if not shared:
            return {"folder": None, "this_device": device_name(),
                    "note": "No brain folder yet: memory stays on this PC. Ask the user which "
                            "folder to use (a synced one shares it across PCs)."}
        imported = sync(shared, database)            # bring in what other PCs already wrote
        exported = export_history(shared, database) if share_existing else None
        from graph_mind.sharing import is_database
        if not is_database(shared):
            where = str(shared)
        elif "@127.0.0.1:" in shared:
            where = "this PC's Postgres"
        else:                                   # never show the password inside the URL
            where = "Postgres on " + shared.rsplit("@", 1)[1].split("/")[0]
        result = {} if shared_out is None else {
            "connection_code": shared_out["connection_code"],
            "reachable_at": shared_out["addresses"], "firewall": shared_out["firewall"]}
        warnings = capture_warnings()
        if warnings:
            result["capture_warnings"] = warnings
        return {**result, "folder": where, "this_device": device_name(),
                "devices": devices(shared),
                "imported_from_other_devices": imported["imported"],
                "existing_memories_shared": exported or "not shared; ask the user before "
                                                       "setting share_existing=true"}

    NAME_REQUIRED = {"status": "NAME_REQUIRED",
                     "note": "Teammates would see this PC's name. Ask the user which name they "
                             "should see (e.g. 고요한), call set_name with it, then do this again."}

    @server.tool(
        name="brain_checkpoint",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=False,
            destructiveHint=False,
            idempotentHint=False,
            openWorldHint=False,
        ),
    )
    def brain_checkpoint(action: Literal["projects", "create_project", "publish", "attach",
                                         "timeline", "retract", "set_instructions", "host",
                                         "invite", "members", "remove_member", "join_team",
                                         "leave_team", "audit", "set_name"],
                         project: str | None = None,
                         type: Literal["decision", "progress", "blocker", "next_action",
                                       "artifact", "release"] | None = None,
                         summary: str | None = None, details: str | None = None,
                         path: str | None = None, workspace: str | None = None,
                         name: str | None = None,
                         checkpoint_id: str | None = None, supersedes: str | None = None,
                         source_refs: REFS = None,
                         instructions: str | None = None, member: str | None = None,
                         role: Literal["owner", "editor", "viewer"] | None = None,
                         projects: list[str] | None = None,
                         code: str | None = None, hub: str | None = None,
                         context: dict[str, Any] | None = None) -> dict[str, Any]:
        """Team project brains: decisions and progress shared with teammates' AIs, per project.

        Not for the user's own memory or their other PCs: that is brain_folder. A project brain
        holds what a team's AIs need to know about a project, apart from the user's personal
        memory and from every other project. Nothing
        personal is shared through this; only what is published here, when the user asks. Files
        and notifications stay in Slack, drives and GitHub; a project brain keeps the decisions,
        the progress, the context and links to where the work is.

        Always pass `workspace` = your current working folder: a folder bound to a project makes
        it the default `project`.

        Publish only when the user asks ("공유해", "프로젝트에 올려줘", "체크포인트 남겨"): that
        request is the approval, so do not ask again; ask only if the project is ambiguous.
        Afterwards say exactly what went where.
        - `projects`: the project brains the user takes part in, with when each was last shared.
        - `create_project` + `project` (+ `path` = folder to bind): only when the user names one.
        - `publish` + `type` + `summary` (one line, user's language) + `details` (a handover
          note: what changed and why, files and functions, test results, links, what is left).
          Never paste conversation text. `supersedes`=<id> replaces an earlier decision.
        - `context` (with publish or attach): what changed, where (pages, sections, files,
          functions), why, verification (test or check results), remaining, review_focus, and
          the ids it answers (`addresses`) and its `evidence` (commit, PR, test log, Slack or
          document links). Write only what you know; what is left out reads "not recorded".
        - `attach` + `path`: a git folder links its commit at the stage it really reached
          (committed / pushed / pr_open / merged / released; never call work done when the stage
          says otherwise); a URL (a Slack message, a drive document) is kept as a link. Files are
          not stored here: if the user wants a file shared, share it in Slack or a drive (with
          the tools for those) and attach the link.
        - `timeline`: "누가 어디까지 했어?" — answer from it only: who, what, what is left, and
          when it was last shared. Do not guess at anything newer. Follow its `instructions`.
        - `retract` + `checkpoint_id` (the publisher, or the project's owner);
          `set_instructions` + `instructions` (owner).
        - Members. Whoever creates a project owns it. `invite` + `member` + `role` (owner /
          editor / viewer) + `projects` returns a code to give them. `members` + `project`;
          `remove_member` + `member` + `project` (owner; or yourself, to leave). `audit`
          (+ `project`). On a teammate's PC: `join_team` + `code` (+ `name`), `leave_team` +
          `project`.
        - Where projects live: on a Postgres hub (`host`: make this PC one; teammates on the
          office network or over Tailscale), where `invite` on the hub's PC also makes their
          account (elsewhere they need an account from the hub's operator first); without a
          hub, on this PC alone. Someone in several team hubs and none of their own:
          `create_project` + `hub` (an address of it).
        - `set_name` + `name`: the name teammates see (else this PC's name). If a result says
          NAME_REQUIRED, ask the user for it (their own name, e.g. 고요한), set it, then retry.
        If the result says UNAVAILABLE, the hub cannot be reached: tell the user the latest
        shared state is unknown right now; never fill in from memory.
        """
        from graph_mind import project_brains as pl
        if not project and action not in ("projects", "members", "join_team", "audit", "host"):
            project = pl.folder_project(workspace)
        ledger = None
        try:
            if action == "projects":
                found, unreachable = pl.ledgers()
                result = {"projects": [{**p, "ledger": book.where} for book in found
                                       for p in book.projects()]}
                for book in found:
                    book.db.close()
                if unreachable:
                    result["unreachable"] = unreachable
                    result["note"] = ("Some project hubs cannot be reached right now; their "
                                      "projects are missing from this list, not gone.")
                return result
            if action == "set_name":
                return pl.set_display_name(name or member or "")
            if action in ("invite", "host") and not pl.named():
                return NAME_REQUIRED
            if action == "host":
                return pl.host_projects()
            if action == "join_team" and (code or "").strip().startswith("gm1."):
                return brain_folder(path=code.strip())     # the user's own other PC's code
            if action == "join_team":
                if not (name or pl.named()):
                    return {**NAME_REQUIRED, "invite_gives": pl._decode_team(code or "")["n"],
                            "note": "Ask the user which name teammates should see (the invite "
                                    "suggests the one in invite_gives), then join_team again "
                                    "with `name`."}
                return pl.join_team(code or "", name or pl.actor())
            if action == "invite":
                names = projects or ([project] if project else [])
                if not names:
                    raise ValueError("PROJECTS_REQUIRED: which projects to add them to")
                ledger = pl.ledger_for(names[0])
                if not ledger.postgres or (ledger.role == pl.OWNER_ROLE and pl._hosts_here()):
                    ledger.db.close()
                    ledger = None              # the owner on the hub's own PC: account + code
                    return pl.invite(member, role or "viewer", names, pl.actor())
                return {"granted": [ledger.grant(p, member, role or "viewer", ledger.by)
                                    for p in names], "ledger": ledger.where,
                        "note": "Added: the projects show up for them now."}
            if action == "members" and not project:
                if not pl._hosts_here():
                    raise ValueError("PROJECT_REQUIRED: whose members, in which project")
                return {"accounts": pl.accounts()}
            if action == "remove_member" and not project:
                # closing a whole account is the operator's, on the hub: never one word away
                raise ValueError("PROJECT_REQUIRED: remove them from which project. To close "
                                 "their account on this hub: graph-mind-hub remove-user <name>")
            if action == "leave_team":
                return pl.leave_team(project or "")
            if action == "audit":
                ledger = pl.ledger_for(project) if project else pl.own_ledger()
                return {"audit": ledger.audit()}
            if not project:
                raise ValueError("PROJECT_REQUIRED: name the project (or bind this folder to "
                                 "one with create_project + path)")
            if action == "create_project":
                ledger = pl.home_ledger(hub)
                if ledger.role in ("", pl.OWNER_ROLE) and not pl.named():
                    return NAME_REQUIRED               # a team hub uses the invite's name
                result = ledger.create_project(project, ledger.by)
                if path:
                    result["bound_folder"] = pl.bind_folder(path, project)["folder"]
                return {**result, "ledger": ledger.where}
            ledger = pl.ledger_for(project)
            by = ledger.by
            if action == "publish":
                result = ledger.publish(project, type, summary, by, details=details,
                                        source_refs=source_refs, supersedes=supersedes,
                                        context=context)
            elif action == "attach":
                if not path:
                    raise ValueError("PATH_REQUIRED: a git folder, or a link")
                result = ledger.attach(project, path, summary, by, kind=type or "artifact",
                                       source_refs=source_refs, details=details,
                                       context=context)
            elif action == "timeline":
                result = {"project": project, "instructions": ledger.instructions(project),
                          "checkpoints": ledger.timeline(project, by=by)}
            elif action == "set_instructions":
                result = ledger.set_instructions(project, instructions, by)
            elif action == "members":
                result = {"project": project, "members": ledger.members(project)}
            elif action == "remove_member":
                result = ledger.revoke(project, member or "", by)
            else:
                result = ledger.retract(checkpoint_id, by)
            return {**result, "ledger": ledger.where}
        except pl.HubUnavailable as error:
            return {"status": "UNAVAILABLE", "unreachable": str(error),
                    "note": "The project hub cannot be reached right now, so its latest shared "
                            "state is unknown. Tell the user that; do not answer from memory "
                            "or guess."}
        except ValueError as error:
            return {"status": "REFUSED", "reason": str(error),
                    **({"ledger": ledger.where} if ledger else {})}
        except Exception as error:                  # a hub that went away mid-call
            return {"status": "UNAVAILABLE", "reason": f"{type_name(error)}: {error}"[:300],
                    "note": "The project hub failed during the request; the latest shared "
                            "state is unknown. Do not guess."}
        finally:
            if ledger is not None:
                ledger.db.close()

    @server.tool(
        name="brain_forget",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=False,
            destructiveHint=True,
            idempotentHint=True,
            openWorldHint=False,
        ),
    )
    def brain_forget(query: str | None = None, ids: list[str] | None = None) -> dict[str, Any]:
        """Delete what the user wants gone from memory: "delete the password I typed earlier",
        "그 토큰 지워줘", "forget what I said about my ex".

        Always two calls. First `query`: what to look for, in general words ("password", "wifi",
        "DB login"); never repeat a secret the user typed. It returns numbered candidates with
        masked previews. Show the user exactly those previews and ask which to delete; never
        quote the original text. Then call again with the `ids` the user picked, and only those.

        Deleting removes them from this PC, its search indexes, the shared memory and the user's
        other PCs. This exchange about deleting is not saved either. The AI app's own chat
        history is separate and untouched (Claude Code keeps ~/.claude/projects).
        """
        import sqlite3

        from graph_mind.forget import forget_ids, masked_preview
        if ids:
            db = sqlite3.connect(database, timeout=30)
            try:
                turns = [row[0] for row in db.execute(
                    "SELECT turn_id FROM conversation_turns WHERE turn_id IN ("
                    + ",".join("?" * len(ids)) + ")", ids)]
                memories = [row[0] for row in db.execute(
                    "SELECT memory_id FROM local_brain_memories WHERE memory_id IN ("
                    + ",".join("?" * len(ids)) + ")", ids)]
            except sqlite3.OperationalError:
                turns, memories = [], []
            finally:
                db.close()
            from graph_mind.sharing import folder
            try:
                shared = folder()
            except Exception:
                shared = None
            result = forget_ids({"turn_ids": turns, "memory_ids": memories}, database, shared)
            return {"status": "FORGOTTEN", **result,
                    "not_found": [i for i in ids if i not in turns and i not in memories]}
        if not query:
            return {"status": "QUERY_OR_IDS_REQUIRED", "candidates": []}
        recalled = gather(database, query, as_of=_now(), limit=10)
        candidates = [{"id": m["memory_id"], "kind": "memory", "when": m.get("effective_at"),
                       "preview": masked_preview(m.get("content", ""))}
                      for m in recalled.get("matches", [])]
        candidates += [{"id": t["turn_id"], "kind": f"{t.get('role')} turn in {t.get('client')}",
                        "when": t.get("happened_at"),
                        "preview": masked_preview(t.get("content", ""))}
                       for t in recalled.get("conversation_turns", [])]
        return {"status": "CANDIDATES", "candidates": candidates,
                "next": "Show these numbered with their masked previews exactly as given, ask "
                        "which to delete, then call brain_forget with those ids."}

    @server.tool(
        name="code_activity",
        structured_output=True,
        annotations=types.ToolAnnotations(
            readOnlyHint=True,
            destructiveHint=False,
            idempotentHint=True,
            openWorldHint=False,
        ),
    )
    def code_activity(project_id: PROJECT_ID = None,
                      happened_from: str | None = None,
                      happened_to: str | None = None,
                      file_path: FILE = None,
                      symbol: str | None = None,
                      change_kind: CHANGE = None,
                      limit: ITEMS = 20,
                      max_diff_chars: DIFF = 6000) -> dict[str, Any]:
        """Code changes the capture service recorded, with diff excerpts, filtered by project,
        time range (`happened_from`/`happened_to`, ISO), file, symbol or kind. For "what did I
        change in auth.py last week?" or "when did the parser change?". Empty unless a code folder
        is being watched (automatic-capture.json, code_workspaces)."""
        try:
            bounded_diff_chars = max(200, min(max_diff_chars, 20000))
            with CodingMemoryStore(database) as store:
                return store.query(project_id=project_id, happened_from=happened_from,
                    happened_to=happened_to, file_path=file_path, symbol=symbol,
                    change_kind=change_kind, limit=limit,
                    include_diff_excerpt=True, max_diff_chars=bounded_diff_chars)
        except ValueError as error:
            return {"status": "UNKNOWN", "reason": "INVALID_CODE_ACTIVITY_QUERY",
                    "detail": str(error), "scope_completeness": "UNATTESTED",
                    "changes": []}

    return server



def preload(database):
    """Load the embedding model while the app is still starting. Importing torch and the model
    took 30-50 s on a OneDrive-synced Windows PC, and the user's first memory question paid it."""
    def work():
        try:
            embedder_for(database).embed(["preload"])
        except Exception:                 # no model on disk: word search still answers
            pass
        try:
            # and one search, so the shared-folder sync and the in-memory index are done too:
            # on a PC sharing its memory (400 MB) the first question otherwise took 3.7-24 s
            gather(database, "preload", as_of=_now(), limit=1, embedder=embedder_for(database))
        except Exception:
            pass
    # after a pause: importing torch while the app is still starting its servers delayed the
    # handshake (19 s inside Codex), and Codex leaves out a server that is not ready yet
    timer = threading.Timer(15, work)
    timer.daemon = True
    timer.start()


def keep_capture_running(every=60.0):
    """An app that relies on the capture service (GRAPH_MIND_CAPTURED, set by the installer)
    keeps it alive: if it died, this server starts it again within a minute."""
    def work():
        from graph_mind.automatic_capture import ensure_service
        try:
            ensure_service()
        except Exception:                 # never let this take the memory server down
            pass
        timer = threading.Timer(every, work)
        timer.daemon = True
        timer.start()
    if os.environ.get("GRAPH_MIND_CAPTURED"):
        work()


def terminal_command(argv):
    """graph-mind folder [PATH | local | share | CODE] [--share-existing]
    graph-mind export FILE | graph-mind import FILE

    What brain_folder leaves to the user: where the memory lives, sharing it with their other
    PCs, and moving it to or from a file."""
    import argparse
    import asyncio
    parser = argparse.ArgumentParser(prog="graph-mind", description=terminal_command.__doc__,
                                     formatter_class=argparse.RawDescriptionHelpFormatter)
    commands = parser.add_subparsers(dest="command", required=True)
    folder = commands.add_parser("folder", help="show or change where the memory lives")
    folder.add_argument("path", nargs="?", help="a folder, local, share, or a gm1./gmt1. code")
    folder.add_argument("--share-existing", action="store_true",
                        help="also send what this PC remembers to the shared memory")
    commands.add_parser("export", help="write the whole memory into a file").add_argument("file")
    commands.add_parser("import", help="add a memory file to this memory").add_argument("file")
    args = parser.parse_args(argv)
    call = ({"path": args.path, "share_existing": args.share_existing}
            if args.command == "folder" else
            {"export_to" if args.command == "export" else "import_from": args.file})
    result = asyncio.run(build_server(terminal=True).call_tool("brain_folder", call))
    print(json.dumps(result.structured_content, ensure_ascii=False, indent=2))
    if args.command == "import":
        wait_for_index()


def main():
    if sys.argv[1:]:
        return terminal_command(sys.argv[1:])
    from graph_mind.local_embedder import LocalEmbedder
    LocalEmbedder.WAIT_FOR_MODEL = 0.5      # an app's question never waits out a model load
    LocalEmbedder.USE_SERVICE = True        # the capture service's model, when it runs
    LocalEmbedder.PACE = True               # a backlog it embeds itself, at half pace
    keep_capture_running()
    preload(configured_db_path())
    build_server().run(transport="stdio")


if __name__ == "__main__":
    main()
