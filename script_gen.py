"""Story script generator for chronicle-forge — three passes.

Pass 1 — Story Narration
  Writes an emotionally-driven story with a protagonist, tension, wonder,
  and arc. LLM annotates delivery with [STRESS]/[PAUSE]/[BEAT] tags;
  convert_narration_tags() strips them to punctuation/caps before TTS.

Pass 2 — Scene Breakdown + Image Prompts
  Mechanical sentence-group splitter (no LLM) decides cut points; then
  batched LLM calls write 10-20 word image prompts per scene (5/call).
  Output: [{text_segment, prompt}]

Pass 3 — Visual Scene Expansion
  Agentic pass: for each scene, the LLM identifies 1-3 distinct visual
  moments (action → reaction, movement → stillness, etc.) and splits the
  scene into sub-scenes with their own image prompts. Runs before image
  generation so expanded scene count drives the image pipeline. Falls
  back to the original scene on any parse error.

All passes are exposed as standalone functions so main.py can checkpoint
after Pass 1 independently — protecting against Pass 2/3 timeouts.
"""
import json
import os
import re
import threading
import time
import requests
from dotenv import load_dotenv

load_dotenv()

OLLAMA_BASE_URL    = os.getenv("OLLAMA_BASE_URL", "http://localhost:11434")
OLLAMA_MODEL       = os.getenv("OLLAMA_MODEL",    "nemotron-3-super:cloud")

WORDS_PER_SECOND   = 2.5
MAX_RESEARCH_CHARS = 4000

MIN_SCENE_DURATION = 4    # seconds — shortest a scene can be
MAX_SCENE_DURATION = 12   # seconds — longest before forcing a new image
MAX_SCENES         = 80   # hard cap regardless of video length
PROMPT_BATCH_SIZE  = 5    # scenes per image-prompt batch — small keeps each call fast


# ── Ollama infrastructure ─────────────────────────────────────────────────────

def check_ollama() -> None:
    """
    Verify Ollama is reachable and the model responds.

    Uses a 1-token generate probe instead of /api/tags so cloud-backed models
    (like nemotron-3-super:cloud) that don't appear in the local model list
    are correctly recognised as available.
    """
    try:
        requests.get(f"{OLLAMA_BASE_URL}/api/tags", timeout=5).raise_for_status()
    except requests.exceptions.ConnectionError:
        raise RuntimeError(
            f"Ollama not reachable at {OLLAMA_BASE_URL}\n"
            "Start it with: ollama serve"
        )

    print(f"  Probing model {OLLAMA_MODEL!r}...", end=" ", flush=True)
    try:
        resp = requests.post(
            f"{OLLAMA_BASE_URL}/api/generate",
            json={"model": OLLAMA_MODEL, "prompt": "Hi",
                  "stream": False, "options": {"num_predict": 1}},
            timeout=60,
        )
        resp.raise_for_status()
        print("OK")
    except requests.exceptions.HTTPError as exc:
        if exc.response is not None and exc.response.status_code == 404:
            raise RuntimeError(
                f"Model {OLLAMA_MODEL!r} not found.\n"
                f"Run: ollama pull {OLLAMA_MODEL}\n"
                f"Or set OLLAMA_MODEL=<model> in .env"
            )
        raise
    except requests.exceptions.Timeout:
        print("slow (>60s for probe) — continuing anyway")


def _strip_think(text: str) -> str:
    """Remove <think>...</think> blocks prepended by reasoning models."""
    return re.sub(r'<think>.*?</think>', '', text, flags=re.DOTALL).strip()


def _ollama_stream(prompt: str, label: str = "Generating",
                   max_wait: int = 120) -> str:
    """
    Stream an Ollama generation with a hard wall-clock deadline.

    Uses a daemon thread so the timeout fires even when the TCP socket stays
    alive (cloud models keep connections open during long thinking phases,
    defeating per-chunk read timeouts). No num_predict cap.
    """
    buf       = []
    error_box = [None]
    done      = threading.Event()

    def _worker():
        try:
            resp = requests.post(
                f"{OLLAMA_BASE_URL}/api/generate",
                json={"model": OLLAMA_MODEL, "prompt": prompt, "stream": True},
                stream=True,
                timeout=(10, 60),
            )
            resp.raise_for_status()
            char_count    = 0
            t0            = time.time()
            last_print_t  = 0.0
            for line in resp.iter_lines():
                if done.is_set():
                    resp.close()
                    return
                if not line:
                    continue
                data  = json.loads(line)
                token = data.get("response", "")
                buf.append(token)
                char_count += len(token)
                now = time.time()
                # suppress during thinking phase (0 chars) and rate-limit to 1/s
                if char_count > 0 and now - last_print_t >= 1.0:
                    elapsed = int(now - t0)
                    print(f"\r  {label}... {char_count} chars ({elapsed}s)",
                          end="", flush=True)
                    last_print_t = now
                if data.get("done"):
                    return
        except Exception as exc:
            error_box[0] = exc
        finally:
            done.set()

    t = threading.Thread(target=_worker, daemon=True)
    t.start()

    try:
        completed = done.wait(timeout=max_wait)
    except KeyboardInterrupt:
        # Ctrl+C fired while waiting for the stream. Signal the worker to close,
        # then return whatever was generated — the caller can save it before exiting.
        done.set()
        t.join(timeout=2)
        text_so_far = _strip_think("".join(buf))
        if text_so_far.strip():
            print(f"\n  Interrupted — {len(text_so_far)} chars generated; returning for save")
            return text_so_far
        raise  # nothing generated — can't recover

    if not completed:
        done.set()
        t.join(timeout=3)
        text_so_far = "".join(buf)
        print(f"\n  Timed out after {max_wait}s ({len(buf)} tokens received)")
        if not text_so_far.strip():
            raise RuntimeError(
                f"Ollama produced no output in {max_wait}s.\n"
                f"Model: {OLLAMA_MODEL}\n"
                f"Test:  ollama run {OLLAMA_MODEL} 'Say hello'"
            )
        print(f"  Returning partial output ({len(text_so_far)} chars)")
        return text_so_far

    print(flush=True)
    if error_box[0] is not None and not buf:
        raise error_box[0]
    return _strip_think("".join(buf))


# ── Fallback ──────────────────────────────────────────────────────────────────

def _auto_split(narration: str, target_seconds: int) -> list:
    """Mechanical fallback when Pass 2 JSON parse fails."""
    sentences = [
        s.strip()
        for s in re.split(r'(?<=[.!?])\s+', narration.strip())
        if s.strip()
    ]
    if not sentences:
        sentences = [narration]

    num_scenes = min(MAX_SCENES, max(3, target_seconds // 6))
    scenes = []
    for i in range(num_scenes):
        start = int(i * len(sentences) / num_scenes)
        end   = int((i + 1) * len(sentences) / num_scenes)
        end   = max(start + 1, min(end, len(sentences)))
        seg   = " ".join(sentences[start:end])
        scenes.append({
            "text_segment": seg,
            "prompt":       seg[:80],   # crude fallback prompt
        })
    return scenes


# ── Tag converter ─────────────────────────────────────────────────────────────

def _convert_narration_tags(text: str) -> str:
    """
    Strip LLM delivery annotation tags → TTS-friendly punctuation/caps.

    [STRESS]word[/STRESS] → WORD    (all-caps for emphasis)
    [PAUSE]               → ...     (trailing suspense / held breath)
    [BEAT]                → —       (mid-sentence pivot or reveal)
    Any other [TAG] is stripped.
    """
    text = re.sub(
        r'\[STRESS\](.*?)\[/STRESS\]',
        lambda m: m.group(1).upper(),
        text, flags=re.IGNORECASE | re.DOTALL,
    )
    text = text.replace('[PAUSE]', '...')
    text = text.replace('[BEAT]',  ' — ')
    text = re.sub(r'\[/?[A-Z]+\]', '', text)
    return text.strip()


# ── Pass 1: Story Narration ───────────────────────────────────────────────────

def _generate_narration(topic: str, target_words: int, research: str) -> str:
    research_block = (
        f"Key facts to incorporate:\n{research[:MAX_RESEARCH_CHARS]}\n\n"
        if research else ""
    )
    prompt = (
        f"Write a {target_words}-word STORY narration for a YouTube video about: \"{topic}\"\n\n"
        f"{research_block}"
        f"This is a STORY, not a documentary. Structure it with YOUTUBE HOOKS that keep viewers watching:\n\n"

        f"HOOK STRUCTURE (critical for retention):\n"
        f"  1. OPENING HOOK (first ~{max(40, target_words // 10)} words): Start mid-action or with a shocking "
        f"fact/question. Do NOT introduce the topic by name. Drop the viewer into a scene.\n"
        f'     Good opening: "He held a vial of liquid so unstable that one wrong move would kill everyone '
        f'in the building."\n'
        f'     Bad opening: "Today we\'re talking about the history of dynamite."\n'
        f"     YOUR FIRST SENTENCE TEST: heard with zero context, would a stranger stop scrolling\n"
        f"     and ask 'wait — what?' If not, rewrite it. Cap it at 10-14 words.\n"
        f"     Lead with consequence or collision. No setup. No context. No name of the topic.\n"
        f"  2. RETENTION HOOK (around {target_words // 2} words in): Insert a curiosity gap that makes stopping "
        f"feel impossible. Use phrases like 'But what nobody knew...', 'And then something changed everything...',\n"
        f"     'The answer would shock the world.', 'This is where the story takes a dark turn.'\n"
        f"  3. PAYOFF (final ~{max(40, target_words // 8)} words): A resonant closing image, consequence, or "
        f"question that lingers after the video ends. Not a summary — an emotional landing.\n\n"

        f"STORY RULES:\n"
        f"- Give the story a protagonist (key person, civilisation, or idea itself) with clear stakes\n"
        f"- Build tension: what stood in the way? What could go wrong? What was the cost?\n"
        f"- Emotional beats: awe, dread, urgency, triumph, tragedy — the viewer must FEEL it\n"
        f"- Vary tone: intense opening → rising stakes → retention hook → revelation → resonant ending\n"
        f"- Short punchy sentences for impact; longer flowing ones to build atmosphere\n"
        f"- Each sentence max 18 words — must sound natural when spoken aloud\n"
        f"- Spell all numbers as words: 'three thousand years ago', not '3,000 years ago'\n"
        f"- Write full names — expand all initials: 'Robert Jay Oppenheimer', not 'Robert J. Oppenheimer'\n"
        f"- Never use phonetic respellings — write names naturally\n"
        f"- No dialogue, no citations, no headings, no bullet points\n\n"
        f"DELIVERY ANNOTATION — embed these tags inside the narration where delivery must shift:\n"
        f"  [STRESS]word[/STRESS]  → that word carries peak weight (ONE per sentence maximum)\n"
        f"  [PAUSE]                → silence before a revelation or turning point\n"
        f"  [BEAT]                 → mid-sentence pivot or sudden reveal (becomes an em-dash)\n"
        f"Be sparing. Most sentences need no tags at all. [STRESS] at 2-3 words per minute max.\n"
        f"[PAUSE] and [BEAT] lose power if overused — one every 3-4 sentences at most.\n\n"
        f"Output ONLY the annotated narration text. No title, no JSON, no commentary."
    )
    print(f"  Pass 1: story narration (~{target_words} words)...")
    return _ollama_stream(prompt, label="Writing story", max_wait=600).strip()


# ── Pass 2a: Scene Cuts (auto-split, no LLM) ─────────────────────────────────
#
# The cloud thinking model (nemotron-3-super:cloud) times out on ANY prompt
# that passes the full narration text as input — even "just decide where to
# cut" exhausts the model's reasoning budget before producing output tokens.
#
# Solution: use the mechanical sentence-group splitter for cut decisions.
# This is not a quality regression — the video composer's TTS word-boundary
# sync (assign_scene_timestamps) controls when each image actually appears
# on screen. Scene boundaries only determine which text_segment gets which
# image prompt, not the exact frame timing.

# ── Pass 2b: Image Prompts (batched LLM, 5 scenes per call) ──────────────────

def _generate_prompts_for_scenes(scenes: list) -> list:
    """
    Write image prompts in batches of PROMPT_BATCH_SIZE (5).

    Each call receives only the 5 scene text segments (~100-200 words input)
    and asks for 5 × 15-20 word prompts — small enough that the thinking
    model completes within 180s. Falls back to text_segment[:80] per scene.
    """
    result    = [dict(s) for s in scenes]
    n         = len(scenes)
    n_batches = (n + PROMPT_BATCH_SIZE - 1) // PROMPT_BATCH_SIZE

    for batch_i in range(n_batches):
        start = batch_i * PROMPT_BATCH_SIZE
        end   = min(start + PROMPT_BATCH_SIZE, n)
        batch = scenes[start:end]

        # Minimal input: just the text excerpts, no narration context.
        # Smaller input → less thinking → faster response from cloud model.
        excerpts = "\n".join(
            f'[{start + j + 1}] "{scene.get("text_segment", "")[:150]}"'
            for j, scene in enumerate(batch)
        )

        prompt = (
            f"For each narration excerpt, write a 10-15 word image prompt "
            f"for a single illustration frame.\n\n"
            f"CRITICAL — depict ACTION, not description:\n"
            f"  - For physical actions (slam, run, throw, collapse, ignite): show the "
            f"PEAK MOMENT — arm at full extension, body mid-recoil, impact happening NOW\n"
            f"  - Describe exact body pose and direction of force, not just 'person near object'\n"
            f"    BAD: 'man standing by car door'\n"
            f"    GOOD: 'man driving fist into car door, arm extended, metal denting'\n"
            f"  - For emotions: face expression + body posture together\n"
            f"  - For explosions/impacts: show the physics — debris flying, people thrown\n"
            f"  - For environments: one strong focal point with implied motion or tension\n\n"
            f"STYLE LOCK — these words are FORBIDDEN in prompts:\n"
            f"  cinematic, photorealistic, dramatic, detailed, render, 3D, realistic,\n"
            f"  photograph, camera, film, shot, lighting, bokeh, HDR, CGI, digital art\n"
            f"  Describe CONTENT only. Style is injected separately.\n\n"
            f"TEXT AND NUMBERS — if the narration mentions a specific year, number, or\n"
            f"  name that would appear visually (on a sign, banner, document, scoreboard):\n"
            f"  include the EXACT digits/spelling. '1969' not 'year', '42' not 'number'.\n"
            f"  Only include text when it genuinely appears as a visual element.\n\n"
            f"{excerpts}\n\n"
            f'Reply with ONLY valid JSON: {{"prompts": ["prompt1", "prompt2", ...]}}'
        )

        label = f"Prompts {start+1}–{end}/{n}"
        print(f"  Pass 2b: {label}...")
        raw = _ollama_stream(prompt, label=label, max_wait=180)

        match = re.search(r'\{.*\}', raw, re.DOTALL)
        if match:
            try:
                data    = json.loads(match.group())
                prompts = data.get("prompts", [])
                for j, p in enumerate(prompts):
                    if start + j < n and isinstance(p, str) and p.strip():
                        result[start + j]["prompt"] = p.strip()
                missing = sum(1 for k in range(start, end) if "prompt" not in result[k])
                if missing:
                    print(f"  Warning: {missing}/{len(batch)} prompts missing — filling with fallback")
                continue
            except (json.JSONDecodeError, ValueError) as exc:
                print(f"  Warning: batch {batch_i + 1} parse error ({exc})")

        print(f"  Warning: batch {batch_i + 1} failed — using text-segment fallback")
        for j, scene in enumerate(batch):
            if "prompt" not in result[start + j]:
                result[start + j]["prompt"] = scene.get("text_segment", "")[:80]

    return result


# ── Pass 3: Visual Scene Expansion ───────────────────────────────────────────

def _expand_scenes_for_visuals(scenes: list, on_batch=None) -> list:
    """
    For each scene, identify 1-3 distinct visual moments and create sub-scenes.

    Batches 3 scenes per LLM call, 180s timeout. Falls back to the original
    scene on any parse error or timeout. Calls on_batch(result_so_far, cursor)
    after every batch so the caller can checkpoint progress to disk.
    """
    result     = []
    batch_size = 3
    n          = len(scenes)

    for batch_start in range(0, n, batch_size):
        batch = scenes[batch_start : batch_start + batch_size]

        scene_block = "\n\n".join(
            f"SCENE {batch_start + j + 1}:\n"
            f'Text: "{scene["text_segment"]}"\n'
            f"Current image: {scene.get('prompt', '')}"
            for j, scene in enumerate(batch)
        )

        prompt = (
            f"You are a visual director breaking narration into distinct screen moments.\n\n"
            f"For each scene, identify 1-3 sub-scenes — moments where the action, emotion,\n"
            f"or visual focus clearly changes on screen.\n\n"
            f"Rules:\n"
            f"  - 'text' MUST be a CHARACTER-FOR-CHARACTER copy of words from the scene.\n"
            f"    Do NOT paraphrase, reorder, trim, or add any words.\n"
            f"    Copy an exact substring. If no clean split exists, return 1 sub-scene.\n"
            f"  - 'prompt' is 10-15 words: subject + action. No style words.\n"
            f"    Forbidden: cinematic, photorealistic, dramatic, render, 3D, realistic,\n"
            f"    photograph, camera, lighting, bokeh, HDR, CGI, detailed, dynamic.\n"
            f"  - Only split when there is a genuine visual change "
            f"(action->reaction, wide->close, movement->stillness)\n"
            f"  - Segments under 10 words: stay as 1 sub-scene unless the shift is very clear\n"
            f"  - Do NOT split mid-sentence for no reason\n\n"
            f"EXAMPLE:\n"
            f'Text: "He opened his notebook. Thinking -- how would this even work?"\n'
            f"-> 3 sub-scenes:\n"
            f'  1. "He opened his notebook."  -- man opening worn notebook on desk, intent\n'
            f'  2. "Thinking --"               -- man pausing, hand on chin, thought forming\n'
            f'  3. "how would this even work?" -- man staring at blank page, puzzled, distant\n\n'
            f"SCENES TO ANALYSE:\n{scene_block}\n\n"
            f"Return ONLY valid JSON. One entry per input scene, in order:\n"
            f'{{"results": [{{"sub_scenes": [{{"text": "...", "prompt": "..."}}]}}]}}'
        )

        label = f"Expanding scenes {batch_start + 1}-{min(batch_start + batch_size, n)}/{n}"
        print(f"  Pass 3: {label}...")

        raw = ""
        try:
            raw = _ollama_stream(prompt, label=label, max_wait=180)
        except RuntimeError:
            print(f"  Warning: Pass 3 {label} timed out (no output) -- keeping originals")

        # Try to parse the LLM response; fall back to originals on any failure.
        parsed_ok = False
        if raw:
            match = re.search(r'\{.*\}', raw, re.DOTALL)
            if match:
                try:
                    data    = json.loads(match.group())
                    results = data.get("results", [])
                    for j, scene_result in enumerate(results):
                        if j >= len(batch):
                            break
                        original   = batch[j]
                        sub_scenes = scene_result.get("sub_scenes", [])
                        valid = [
                            s for s in sub_scenes
                            if isinstance(s.get("text"), str)
                            and isinstance(s.get("prompt"), str)
                            and s["text"].strip() and s["prompt"].strip()
                        ]
                        if len(valid) >= 2:
                            for s in valid:
                                result.append({
                                    "text_segment": s["text"].strip(),
                                    "prompt":       s["prompt"].strip(),
                                })
                        else:
                            result.append(dict(original))
                    # Any scenes the LLM omitted: keep original
                    for k in range(len(results), len(batch)):
                        result.append(dict(batch[k]))
                    parsed_ok = True
                except (json.JSONDecodeError, ValueError, IndexError, KeyError) as exc:
                    print(f"  Warning: Pass 3 batch parse error ({exc}) -- keeping originals")

        if not parsed_ok:
            result.extend(dict(s) for s in batch)

        # Checkpoint after every batch regardless of success/fallback.
        if on_batch:
            on_batch(list(result), batch_start + len(batch))

    return result


# ── Public API ────────────────────────────────────────────────────────────────

def generate_narration(topic: str, target_seconds: int,
                       research_summary: str) -> str:
    """Pass 1 only — callable independently so main.py can checkpoint after it."""
    target_words = int(target_seconds * WORDS_PER_SECOND)
    narration = _generate_narration(topic, target_words, research_summary)
    if not narration:
        raise RuntimeError(
            "Narration generation produced empty output.\n"
            f"Test: ollama run {OLLAMA_MODEL} 'Write one sentence about history.'"
        )
    print(f"  Narration: {len(narration.split())} words")
    return narration


def generate_scenes_with_prompts(narration: str, target_seconds: int,
                                  topic: str = "") -> list:
    """
    Pass 2: auto-split scene cuts + batched LLM image prompts.

    Scene cuts: _auto_split (instant, no LLM) — the thinking model exhausts
    its reasoning budget on any prompt containing the full narration text,
    so scene boundaries are determined mechanically (sentence groups within
    MIN/MAX_SCENE_DURATION). TTS word-boundary sync handles actual image
    timing, so cut quality has minimal effect on the final video.

    Image prompts: 5 scenes per LLM call, 180s timeout, minimal input.
    """
    scenes = _auto_split(narration, target_seconds)
    print(f"  Pass 2a: {len(scenes)} scenes (auto-split)")
    scenes = _generate_prompts_for_scenes(scenes)
    print(f"  Pass 2 complete: {len(scenes)} scenes with prompts")
    return scenes


def expand_scenes(scenes: list, on_batch=None) -> list:
    """
    Pass 3 -- visual sub-scene expansion.

    Takes the Pass 2 scene list and splits scenes at visual transition
    points, returning an expanded list with additional image prompts.
    on_batch(partial_result, cursor) is called after each batch so the
    caller can checkpoint progress to disk between batches.
    """
    expanded = _expand_scenes_for_visuals(scenes, on_batch=on_batch)
    added    = len(expanded) - len(scenes)
    print(f"  Pass 3 complete: {len(scenes)} scenes -> {len(expanded)} "
          f"({'+' if added >= 0 else ''}{added} sub-scenes)")
    return expanded


def convert_narration_tags(text: str) -> str:
    """
    Convert [STRESS]/[PAUSE]/[BEAT] delivery tags → TTS punctuation/caps.
    Call this on the raw Pass 1 output before saving to video_data.
    """
    return _convert_narration_tags(text)


def generate_thumbnail_prompt(topic: str, youtube_title: str, narration: str) -> tuple:
    """
    Generate a thumbnail image prompt + punchy headline via LLM.
    Returns (image_prompt, headline) — both strings.
    """
    prompt = (
        f"Create YouTube thumbnail content for a video about: \"{topic}\"\n"
        f"YouTube title: \"{youtube_title}\"\n"
        f"Story opening: {narration[:400]}\n\n"

        f"Generate TWO things:\n"
        f"1. IMAGE PROMPT — 10-14 words: ONE dramatic visual moment, single clear subject.\n"
        f"   Must work at small size (phone screen) — bold contrast, nothing subtle.\n"
        f"   Think: the single image that makes someone stop scrolling.\n"
        f"   Forbidden words: cinematic, dramatic, realistic, render, 3D, photorealistic,\n"
        f"   detailed, dynamic, stunning. Content only, no style adjectives.\n"
        f"2. HEADLINE — 3-5 words in ALL CAPS. Punchy. Shock or urgency.\n"
        f"   This text overlays on the image. Short enough to read in 1 second.\n\n"
        f"Reply ONLY with valid JSON (no markdown):\n"
        f'{{"image_prompt": "...", "headline": "..."}}'
    )

    raw   = _ollama_stream(prompt, label="Thumbnail prompt", max_wait=120)
    match = re.search(r'\{.*?\}', raw, re.DOTALL)
    if match:
        try:
            data    = json.loads(match.group())
            img_p   = data.get("image_prompt", "").strip().strip('"')
            headline = data.get("headline", "").strip().strip('"')
            if img_p:
                # Cap image prompt at 15 words
                img_p = " ".join(img_p.split()[:15])
                return img_p, headline or youtube_title[:35]
        except (json.JSONDecodeError, KeyError):
            pass

    first_sentence = (narration.split(".")[0])[:80] if narration else topic
    return first_sentence, youtube_title[:35]
