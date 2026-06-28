from __future__ import annotations

import json
import re
import urllib.error
import urllib.request
from pathlib import Path

from v2.providers.openai import _configured_value, _context_block, _read_dotenv
from v2.schemas import AnswerWithSources, Chunk, RelationTriple

PODCAST_TEMPLATE_PATH = Path(__file__).resolve().parents[1] / "prompts" / "5min_podcast_script_template_long.txt"


class OllamaProviderError(RuntimeError):
    pass


class OllamaProvider:
    DEFAULT_MODEL = "gemma2:2b"

    def __init__(
        self,
        model: str | None = None,
        base_url: str | None = None,
        timeout: int = 120,
    ) -> None:
        dotenv = _read_dotenv()
        self.model = model or _configured_value("OLLAMA_MODEL", dotenv, self.DEFAULT_MODEL)
        self.base_url = (base_url or _configured_value("OLLAMA_BASE_URL", dotenv, "http://127.0.0.1:11434")).rstrip("/")
        self.timeout = timeout

    def summarize(self, chunks: list[Chunk]) -> str:
        prompt = (
            "You must write the entire output in Korean only. Write a concise study summary using only the source chunks below. "
            "Do not invent facts. Mention source locations naturally when useful.\n\n"
            f"{_context_block(chunks)}"
        )
        return self._generate(prompt, max_tokens=900)

    def answer(self, question: str, chunks: list[Chunk], graph_context: list[RelationTriple]) -> AnswerWithSources:
        prompt = (
            "You must write the entire output in Korean only. Answer using only the source chunks below. "
            "If the sources are insufficient, say so.\n\n"
            f"Question: {question}\n\n{_context_block(chunks)}"
        )
        return AnswerWithSources(answer=self._generate(prompt, max_tokens=700), vector_sources=[], graph_context=graph_context)

    def extract_relations(self, chunks: list[Chunk]) -> list[RelationTriple]:
        return []

    def generate_script(
        self,
        chunks: list[Chunk],
        minutes: int,
        style: str = "briefing",
        grounding: str = "creative",
        target_chars: int | None = None,
    ) -> str:
        target_words = f"{target_chars} Korean characters" if target_chars else ("3000-4500" if minutes >= 8 else ("1200-1600" if minutes >= 5 else "450-700"))
        grounding = grounding if grounding in {"creative", "strict"} else "creative"
        if style == "podcast":
            if target_chars and target_chars >= 5000:
                return self._generate_podcast_by_scenes(chunks, minutes=minutes, grounding=grounding, target_chars=target_chars)
            template = _load_prompt_template(PODCAST_TEMPLATE_PATH)
            grounding_instruction = (
                "Use the source chunks as the main content. You may add natural host transitions, light analogies, "
                "listener-friendly explanations, and simple examples when they help the podcast flow. Keep them consistent with the sources."
                if grounding == "creative"
                else "Use only facts, examples, numbers, lecture weeks, and terms that appear in the source chunks. Do not add outside examples."
            )
            prompt = (
                "You write Korean study podcasts for BeePDF. Write the entire output in Korean only. "
                "Make it sound like a relaxed two-person podcast, not a summary note, interview checklist, quiz, or flashcard drill. "
                "Use exactly these speaker labels at the start of each turn: HOST: and GUEST:. "
                "Follow the timing and flow of the provided 5-minute podcast template: opening, problem framing, core point 1, core point 2, applied example, recap, and closing question. "
                "Do not copy the template placeholders literally. Fill the template using the source chunks and output only the final podcast script. "
                "If a target character count is provided, prioritize that count over the minute estimate. For 6000 Korean characters, write 24 to 34 rich turns. For 8 minutes or more, write 22 to 30 rich turns. Otherwise write 14 to 20 rich turns. Do not write one-sentence turns. "
                "The HOST must not simply ask question after question. At least half of HOST turns should be reactions, paraphrases, listener-empathy comments, or bridges to the next idea instead of direct questions. Keep direct HOST questions rare and purposeful. "
                "Each HOST turn should usually have 2 to 3 complete spoken sentences. Each GUEST turn must have 4 to 7 complete spoken sentences with explanation, example, contrast, or recap. "
                "The conversation should have a clear arc: opening problem, concept explanation, why learners get confused, applied example, recap, and closing study question. "
                "The GUEST should explain the lecture content slowly with examples, contrasts, common misunderstandings, and short recaps. For long podcasts, expand each source point by explaining why it matters, what learners often miss, and how it connects to the next concept. "
                "Avoid repeated definitions. Once a concept is defined, build on it instead of defining it again. "
                f"Grounding mode: {grounding}. {grounding_instruction} "
                "English is allowed only for source terms such as BPE, OOV, RNN, LSTM, CNN, subword, n-gram, or token. "
                f"Target length: {target_words}. Do not end early. If target_chars is provided, write at least 90 percent of that many Korean characters before the closing. Minute estimate: about {minutes} minutes.\n\n"
                "PODCAST TEMPLATE:\n"
                f"{template}\n\n"
                "SOURCE CHUNKS:\n"
                f"{_context_block(chunks, max_chars_per_chunk=1200)}"
            )
        else:
            prompt = (
                "You write Korean study audio scripts for BeePDF. Write the entire script in Korean only. "
                "Use only the source chunks below and do not invent facts. Write a natural narration script, not bullet points. "
                "Do not use Markdown headings, tables, or lists. Split the script into 6 to 8 spoken paragraphs separated by blank lines. "
                "Include an opening, lecture-by-lecture flow, key concept explanation, recap, and closing. "
                "Mention filename/page evidence naturally when useful. English is allowed only for source terms such as BPE, OOV, RNN, LSTM, or CNN. "
                f"Target length: {target_words}. Do not end early. If target_chars is provided, write at least 90 percent of that many Korean characters before the closing. Minute estimate: about {minutes} minutes.\n\n"
                f"{_context_block(chunks, max_chars_per_chunk=1200)}"
            )
        max_tokens = 12000 if target_chars and target_chars >= 6000 else (8000 if minutes >= 8 else (3000 if minutes >= 5 else 1400))
        return self._generate(prompt, max_tokens=max_tokens)

    def _generate_podcast_by_scenes(
        self,
        chunks: list[Chunk],
        minutes: int,
        grounding: str,
        target_chars: int,
    ) -> str:
        grounding_instruction = (
            "Use the source chunks as the main content. You may add natural transitions, learner-friendly analogies, "
            "and simple examples when they help the conversation. Keep them consistent with the sources."
            if grounding == "creative"
            else "Use only facts, examples, and terms that appear in the source chunks. Do not add outside examples."
        )
        context = _context_block(chunks, max_chars_per_chunk=1400)
        scene_plan = [
            {"id": "opening_problem", "title": "opening and learner problem", "focus": "Open with the learner problem: the terms BPE, OOV, RNN, LSTM, and CNN feel separate, but they belong to one NLP pipeline. Preview the arc without defining everything.", "avoid": "Do not explain BPE merges, LSTM gates, or CNN filters in detail yet.", "chars": 700},
            {"id": "bpe_oov", "title": "BPE and OOV", "focus": "Explain BPE, OOV, subword vocabulary, lower/lowest/newer, and the vocabulary size versus expressiveness tradeoff.", "avoid": "Do not explain RNN, LSTM, or CNN except one short bridge at the end.", "chars": 900},
            {"id": "rnn_lstm", "title": "RNN and LSTM sequence flow", "focus": "Explain hidden state, sequence modeling, gradient vanishing, and how LSTM gates preserve or forget information.", "avoid": "Do not redefine BPE. Do not explain CNN yet.", "chars": 900},
            {"id": "cnn_text", "title": "CNN text classification", "focus": "Explain text CNNs, n-gram-like local patterns, convolution filters, pooling, and why CNNs help classification.", "avoid": "Do not repeat BPE/OOV or LSTM gate details.", "chars": 900},
            {"id": "pipeline", "title": "full NLP pipeline connection", "focus": "Connect tokenization, embedding, model choice, and task. Show where BPE, RNN/LSTM, and CNN each sit in the pipeline.", "avoid": "Do not use a glossary style. Keep this as a spoken bridge.", "chars": 850},
            {"id": "worked_example", "title": "worked example", "focus": "Walk through one concrete input from tokenization to model behavior to classification. Make it feel like a process, not a list.", "avoid": "Do not introduce unrelated models or new topics.", "chars": 950},
            {"id": "recap_closing", "title": "recap and closing question", "focus": "Close with three takeaways, correct common misunderstandings, and leave two study questions.", "avoid": "Do not preview another episode. Do not add new concepts.", "chars": 800},
        ]
        outline_prompt = (
            "You are planning a Korean study podcast for BeePDF. Return a compact Korean outline only. "
            "Do not write the script yet. The episode must sound conversational, not like a Q&A drill. "
            "For each scene, state the listener emotion, the main point, and the transition into the next scene.\n\n"
            f"Grounding mode: {grounding}. {grounding_instruction}\n\n"
            "SOURCE CHUNKS:\n"
            f"{context}"
        )
        outline = self._generate(outline_prompt, max_tokens=1400)

        scene_outputs: list[str] = []
        covered: list[str] = []
        for index, scene in enumerate(scene_plan, start=1):
            scene_prompt = (
                "You are writing one scene of a Korean two-person educational podcast. "
                "Output Korean dialogue only. Every turn must start with exactly HOST: or GUEST:. "
                "No Markdown, no headings, no timestamps, no bullet points, no JSON, no narrator notes. "
                "This must feel like a real podcast conversation, not an interview checklist.\n\n"
                f"Scene {index} of {len(scene_plan)}: {scene['title']}\n"
                f"Scene focus: {scene['focus']}\n"
                f"Avoid: {scene['avoid']}\n"
                f"Already covered scene ids: {', '.join(covered) if covered else 'none'}\n"
                f"Target length for this scene: about {scene['chars']} Korean characters.\n\n"
                "Hard dialogue structure for this scene:\n"
                "- Write exactly 4 turns: HOST, GUEST, HOST, GUEST.\n"
                "- The first HOST turn must be a reaction, listener-empathy statement, or bridge. It must not be a direct question.\n"
                "- The second HOST turn may ask one natural question, or may be a bridge statement.\n"
                "- Each GUEST turn must be 4 to 6 spoken sentences and should explain slowly with an example, contrast, or short recap.\n"
                "- Do not repeat definitions from earlier scenes. Build on them.\n"
                "- Do not close the whole episode unless this is the final scene.\n\n"
                "Episode outline:\n"
                f"{outline}\n\n"
                "SOURCE CHUNKS:\n"
                f"{context}"
            )
            raw_scene = self._generate(scene_prompt, max_tokens=2600)
            scene_text = _clean_dialogue_text(raw_scene)
            if not _has_dialogue_labels(scene_text):
                scene_text = raw_scene.strip()
            scene_outputs.append(scene_text)
            covered.append(scene["id"])

        combined = "\n\n".join(scene_outputs)
        repair_prompt = (
            "You are a Korean podcast script editor. Polish the combined scene script below into one coherent episode. "
            "Keep Korean dialogue only. Every turn must start with exactly HOST: or GUEST:. "
            "No Markdown, no headings, no timestamps, no bullet points, no JSON, no narrator notes.\n\n"
            "Repair goals:\n"
            "- Preserve the same content and order.\n"
            "- Make transitions smoother between scenes.\n"
            "- Remove duplicated definitions.\n"
            "- HOST should mostly react, paraphrase, and bridge; avoid question-after-question rhythm.\n"
            "- Keep 24 to 34 total rich turns.\n"
            "- Keep the final length near the requested target; do not compress aggressively.\n"
            f"- Target length: at least {int(target_chars * 0.85)} Korean characters including spaces.\n\n"
            "Combined scene script:\n"
            f"{combined}"
        )
        repaired = _clean_dialogue_text(self._generate(repair_prompt, max_tokens=12000))
        if _has_dialogue_labels(repaired) and len(repaired) >= int(len(combined) * 0.65):
            return repaired
        return combined

    def _generate(self, prompt: str, max_tokens: int = 1000) -> str:
        payload = {
            "model": self.model,
            "prompt": prompt,
            "stream": False,
            "options": {
                "num_predict": max_tokens,
                "temperature": 0.4,
            },
        }
        request = urllib.request.Request(
            f"{self.base_url}/api/generate",
            data=json.dumps(payload).encode("utf-8"),
            headers={"Content-Type": "application/json"},
            method="POST",
        )
        try:
            with urllib.request.urlopen(request, timeout=self.timeout) as response:
                data = json.loads(response.read().decode("utf-8"))
        except urllib.error.HTTPError as exc:
            detail = exc.read().decode("utf-8", errors="ignore")
            raise OllamaProviderError(f"Ollama request failed with HTTP {exc.code}: {detail[:500]}") from exc
        except urllib.error.URLError as exc:
            raise OllamaProviderError(f"Ollama request failed: {exc.reason}") from exc

        text = str(data.get("response") or "").strip()
        if not text:
            raise OllamaProviderError("Ollama returned an empty response.")
        return text


def _clean_dialogue_text(text: str) -> str:
    text = text.replace("\r\n", "\n").replace("\r", "\n").replace("**", "")
    text = re.sub(r"<think>.*?</think>", "", text, flags=re.DOTALL | re.IGNORECASE)
    text = re.sub(r"```(?:\w+)?", "", text)
    text = text.replace("```", "")
    text = re.sub(r"\s+(HOST|GUEST)\s*[:\uff1a]", r"\n\n\1: ", text, flags=re.IGNORECASE)
    lines = []
    for raw_line in text.splitlines():
        line = raw_line.strip().strip("*- ")
        if not line:
            continue
        if line.startswith("#") or line.startswith("[") or line.startswith("{") or line.startswith("}"):
            continue
        lines.append(line)
    return "\n".join(lines).strip()


def _has_dialogue_labels(text: str) -> bool:
    return bool(re.search(r"(?im)^\s*HOST\s*[:\uff1a]", text)) and bool(re.search(r"(?im)^\s*GUEST\s*[:\uff1a]", text))


def _load_prompt_template(path: Path) -> str:
    try:
        return path.read_text(encoding="utf-8-sig").strip()
    except OSError:
        return "Opening -> problem framing -> core concepts -> example -> recap -> closing question"
