#!/usr/bin/env python3
"""
core/colab_runner.py
Batch extraction runner optimized for Google Colab Free Tier (Local T4 GPU).
Runs open-weight models (Qwen-2.5 / Llama-3) directly on the Colab GPU without any API keys!
Features auto-checkpointing, error recovery, and zero data-loss batching.
"""

import os
import re
import sys
import json
import time
from pathlib import Path
from typing import List, Dict, Any, Optional

# Prevent PyTorch CUDA memory fragmentation on Nvidia GPUs (T4 / A100)
os.environ["PYTORCH_CUDA_ALLOC_CONF"] = "expandable_segments:True"

try:
    from core.srt_parser import parse_srt_file, chunk_transcript_for_extraction
    from core.extractor_prompt import EXTRACTION_SYSTEM_PROMPT, USER_EXTRACTION_PROMPT_TEMPLATE
except (ImportError, ValueError):
    from .srt_parser import parse_srt_file, chunk_transcript_for_extraction
    from .extractor_prompt import EXTRACTION_SYSTEM_PROMPT, USER_EXTRACTION_PROMPT_TEMPLATE

BASE_DIR = Path(__file__).resolve().parent.parent

# Persistent Google Drive support for Colab environment
DRIVE_BASE = Path("/content/drive/MyDrive/yt-ch")
if os.path.exists("/content/drive/MyDrive"):
    DATA_DIR = DRIVE_BASE / "data"
    DOWNLOADS_DIR = DRIVE_BASE / "Downloads"
else:
    DATA_DIR = BASE_DIR / "data"
    DOWNLOADS_DIR = BASE_DIR / "Downloads"

DATA_DIR.mkdir(parents=True, exist_ok=True)
OUTPUT_JSONL = DATA_DIR / "extracted_qa.jsonl"
CHECKPOINT_FILE = DATA_DIR / "extraction_checkpoint.json"
LIVE_LOG_FILE = DATA_DIR / "extraction_live.log"


def log_extracted_unit_live(unit: Dict[str, Any]):
    """Appends newly extracted Q&A unit to a live human-readable log file on Drive."""
    try:
        DATA_DIR.mkdir(parents=True, exist_ok=True)
        ts_now = time.strftime("%Y-%m-%d %H:%M:%S")
        cat = unit.get("topic_category", "General")
        q_text = unit.get("question_ar") or unit.get("question_en") or "Untitled Question"
        ans_text = unit.get("core_answer_summary_ar") or unit.get("core_answer_summary_en") or ""
        with open(LIVE_LOG_FILE, "a", encoding="utf-8") as f:
            f.write(
                f"[{ts_now}] [{unit.get('timestamp_formatted', '00:00')}] [{cat}]\n"
                f"❓ {q_text}\n"
                f"💡 {ans_text[:140]}...\n"
                f"🔗 {unit.get('timestamp_url', '')}\n"
                f"{'-'*75}\n"
            )
    except Exception:
        pass


def load_checkpoints() -> Dict[str, Any]:
    """Loads already processed video IDs to avoid re-processing."""
    if CHECKPOINT_FILE.exists():
        try:
            with open(CHECKPOINT_FILE, "r", encoding="utf-8") as f:
                return json.load(f)
        except Exception:
            return {"processed_video_ids": [], "total_qa_extracted": 0}
    return {"processed_video_ids": [], "total_qa_extracted": 0}


def save_checkpoints_dict(state: Dict[str, Any]):
    """Saves the complete checkpoints dictionary directly."""
    DATA_DIR.mkdir(parents=True, exist_ok=True)
    with open(CHECKPOINT_FILE, "w", encoding="utf-8") as f:
        json.dump(state, f, ensure_ascii=False, indent=2)


def save_checkpoint(video_id: str, count_extracted: int):
    """Saves progress after each video is processed."""
    state = load_checkpoints()
    if video_id not in state["processed_video_ids"]:
        state["processed_video_ids"].append(video_id)
        state["total_qa_extracted"] = state.get("total_qa_extracted", 0) + count_extracted
    save_checkpoints_dict(state)


def append_extracted_units(units: List[Dict[str, Any]]):
    """Appends extracted Q&A units to the JSONL dataset."""
    DATA_DIR.mkdir(parents=True, exist_ok=True)
    with open(OUTPUT_JSONL, "a", encoding="utf-8") as f:
        for unit in units:
            f.write(json.dumps(unit, ensure_ascii=False) + "\n")


def clean_llm_json_response(raw_text: str) -> List[Dict[str, Any]]:
    """Strips markdown code fences and parses JSON safely."""
    text = raw_text.strip()
    if text.startswith("```"):
        text = re.sub(r"^```(?:json)?\s*", "", text)
        text = re.sub(r"\s*```$", "", text)
    try:
        data = json.loads(text)
        if isinstance(data, list):
            return data
        elif isinstance(data, dict):
            for v in data.values():
                if isinstance(v, list):
                    return v
            return [data]
        return []
    except json.JSONDecodeError:
        # Regex fallback to find JSON array
        match = re.search(r"\[\s*\{.*\}\s*\]", text, re.DOTALL)
        if match:
            try:
                return json.loads(match.group(0))
            except Exception:
                pass
        return []


class LocalGPUClient:
    """
    Runs an open-weight model directly on the Google Colab GPU (T4 / A100 / V5e).
    Zero API keys, zero external internet dependencies, zero rate limits.
    """
    def __init__(self, model_name: str = "Qwen/Qwen2.5-7B-Instruct", load_in_4bit: bool = True):
        import torch
        from transformers import AutoModelForCausalLM, AutoTokenizer

        print(f"[+] Initializing Local GPU Model: {model_name}")
        print(f"[+] CUDA Available: {torch.cuda.is_available()}")
        if torch.cuda.is_available():
            print(f"[+] GPU Device: {torch.cuda.get_device_name(0)}")

        self.tokenizer = AutoTokenizer.from_pretrained(model_name)
        
        quant_config = None
        if load_in_4bit and torch.cuda.is_available():
            try:
                from transformers import BitsAndBytesConfig
                quant_config = BitsAndBytesConfig(
                    load_in_4bit=True,
                    bnb_4bit_compute_dtype=torch.float16,
                    bnb_4bit_quant_type="nf4",
                    bnb_4bit_use_double_quant=True
                )
            except ImportError:
                print("[-] bitsandbytes not found, continuing without 4-bit quant.")
        elif not torch.cuda.is_available():
            print("   ⚠️ NOTE: Running on CPU without GPU acceleration!")
            print("   💡 bitsandbytes 4-bit is disabled on CPU. Switch to T4 GPU for 20x faster extraction.")

        model_kwargs = {
            "device_map": "auto",
            "quantization_config": quant_config if torch.cuda.is_available() else None,
            "torch_dtype": torch.float16 if torch.cuda.is_available() else torch.float32,
        }
        if torch.cuda.is_available():
            try:
                # Enable PyTorch native Scaled Dot-Product Attention for 25-40% faster inference on T4
                model_kwargs["attn_implementation"] = "sdpa"
            except Exception:
                pass

        self.model = AutoModelForCausalLM.from_pretrained(
            model_name,
            **model_kwargs
        )
        print("[+] Model loaded into GPU VRAM successfully!")

    def extract(self, prompt: str) -> str:
        messages = [
            {"role": "system", "content": EXTRACTION_SYSTEM_PROMPT},
            {"role": "user", "content": prompt}
        ]
        text_input = self.tokenizer.apply_chat_template(
            messages,
            tokenize=False,
            add_generation_prompt=True
        )
        inputs = self.tokenizer([text_input], return_tensors="pt").to(self.model.device)

        # Collect exact stop tokens to terminate generation as soon as JSON ends
        eos_ids = [self.tokenizer.eos_token_id]
        for special_token in ["<|im_end|>", "<|endoftext|>"]:
            tok_id = self.tokenizer.convert_tokens_to_ids(special_token)
            if tok_id is not None and tok_id not in eos_ids:
                eos_ids.append(tok_id)

        import torch
        # inference_mode() disables version tracking, view tracking, and is ~10-15% faster than no_grad()
        try:
            with torch.inference_mode():
                generated_ids = self.model.generate(
                    **inputs,
                    max_new_tokens=900,
                    temperature=0.2,
                    top_p=0.9,
                    do_sample=True,
                    eos_token_id=eos_ids,
                    pad_token_id=self.tokenizer.pad_token_id or self.tokenizer.eos_token_id
                )
                
            generated_ids = [
                output_ids[len(input_ids):] for input_ids, output_ids in zip(inputs.input_ids, generated_ids)
            ]
            response = self.tokenizer.batch_decode(generated_ids, skip_special_tokens=True)[0]
            return response
        finally:
            del inputs
            if torch.cuda.is_available():
                torch.cuda.empty_cache()


class ExtractionClient:
    """Universal client supporting Local Colab GPU or API fallback."""
    def __init__(self, provider: str = "local_gpu", model_name: str = "Qwen/Qwen2.5-7B-Instruct"):
        self.provider = provider.lower()
        if self.provider == "local_gpu":
            self.client = LocalGPUClient(model_name=model_name, load_in_4bit=True)
        elif self.provider == "gemini":
            import google.generativeai as genai
            genai.configure(api_key=os.environ.get("GEMINI_API_KEY"))
            self.model = genai.GenerativeModel(
                model_name="gemini-1.5-flash",
                system_instruction=EXTRACTION_SYSTEM_PROMPT
            )
        else:
            raise ValueError(f"Unknown provider: {provider}")

    def extract(self, prompt: str) -> str:
        if self.provider == "local_gpu":
            return self.client.extract(prompt)
        elif self.provider == "gemini":
            res = self.model.generate_content(
                prompt,
                generation_config={"temperature": 0.2, "response_mime_type": "application/json"}
            )
            return res.text
        return "[]"


def is_corrupted_youtube_caption(text: str) -> bool:
    """Detects transcripts generated by YouTube ASR hallucinating English over Arabic audio or noise."""
    text_lower = text.lower()
    gibberish_signals = [
        'arda turan', 'pastry shop', 'e-star co2', 'les powder', 'smirk 4', 
        'tomato sauce or muslims', 'swearing copies', 'spyware this line'
    ]
    if any(sig in text_lower for sig in gibberish_signals):
        return True

    words = re.findall(r'[a-z]{3,}', text_lower)
    if len(words) < 50:
        return True

    debate_words = {
        'god', 'allah', 'prophet', 'jesus', 'christian', 'muslim', 'quran', 'bible', 
        'islam', 'trinity', 'atheist', 'faith', 'creator', 'evidence', 'resurrection', 
        'shia', 'sunni', 'church', 'prayer', 'sin', 'heaven', 'hell', 'moral', 'morality', 
        'science', 'universe', 'creation', 'believe', 'religion', 'truth', 'human', 'life', 'book'
    }
    found = sum(1 for w in debate_words if w in text_lower)
    if found < 2:
        return True
    return False


def process_video(
    video_record: Dict[str, Any],
    client: Any,
    chunk_duration_sec: float = 240.0,
    overlap_duration_sec: float = 30.0,
    verbose: bool = True
) -> List[Dict[str, Any]]:
    """Processes a single video by chunking its transcript and extracting all Q&As."""
    raw_srt_rel = video_record.get("srt_file", "").replace("\\", "/")
    filename = video_record.get("srt_filename") or Path(raw_srt_rel).name

    candidate_paths = [
        BASE_DIR / raw_srt_rel,
        BASE_DIR / "Downloads" / filename,
        DOWNLOADS_DIR / filename,
        DRIVE_BASE / raw_srt_rel,
        DRIVE_BASE / "Downloads" / filename,
        Path("/content/drive/MyDrive/yt-ch/Downloads") / filename,
        Path("/content/drive/MyDrive/yt-ch") / raw_srt_rel,
    ]

    srt_path = None
    for p in candidate_paths:
        if p.exists():
            srt_path = p
            break

    if not srt_path:
        return None

    cues = parse_srt_file(srt_path)
    if not cues:
        return None

    video_id = video_record["video_id"]
    title_ar = video_record.get("title_ar", "")

    # Pre-filter: Check if transcript is YouTube acoustic noise before running heavy GPU passes
    full_text = " ".join(c.text for c in cues)
    if is_corrupted_youtube_caption(full_text):
        if verbose:
            print(f"\n🎬 [{video_id}] {title_ar}", flush=True)
            print(f"   ⏭️ Skipped in 0.01s: Corrupted YouTube auto-caption (acoustic noise / non-English audio)\n", flush=True)
        return []

    chunks = chunk_transcript_for_extraction(
        cues,
        chunk_duration_sec=chunk_duration_sec,
        overlap_duration_sec=overlap_duration_sec
    )

    all_units = []
    youtube_base = video_record.get("youtube_url", f"https://www.youtube.com/watch?v=YC86BQwvHyk")

    total_duration = cues[-1].end_sec if hasattr(cues[-1], 'end_sec') else 0.0
    dur_min = int(total_duration // 60)
    dur_sec = int(total_duration % 60)

    if verbose:
        print(f"\n🎬 [{video_id}] {title_ar}", flush=True)
        print(f"   ⏱️ Duration: {dur_min:02d}:{dur_sec:02d} | Cues: {len(cues)} | Chunks: {len(chunks)}", flush=True)

    for i, chunk in enumerate(chunks):
        # Skip chunks that have almost no spoken dialogue (e.g. music, intro/outro silence)
        if len(chunk["text"].strip()) < 80:
            if verbose:
                print(f"   ├─ ⏭️ Chunk {i+1}/{len(chunks)} [{chunk['start_fmt']} -> {chunk['end_fmt']}]: Skipped (no dialogue)", flush=True)
            continue

        if verbose:
            print(f"   ├─ ⏳ Chunk {i+1}/{len(chunks)} [{chunk['start_fmt']} -> {chunk['end_fmt']}]: Extracting on GPU...", end="", flush=True)

        prompt = USER_EXTRACTION_PROMPT_TEMPLATE.format(
            title_ar=title_ar,
            youtube_url=youtube_base,
            start_fmt=chunk["start_fmt"],
            end_fmt=chunk["end_fmt"],
            transcript_text=chunk["text"]
        )

        t0 = time.time()
        try:
            raw_output = client.extract(prompt)
            t_chunk = round(time.time() - t0, 1)
            extracted = clean_llm_json_response(raw_output)

            chunk_units = []
            for item in extracted:
                ts_sec = item.get("timestamp_seconds", int(chunk["start_sec"]))
                if ts_sec < chunk["start_sec"]:
                    ts_sec = int(chunk["start_sec"])

                item["id"] = f"{video_id}_{len(all_units) + 1:03d}"
                item["video_id"] = video_id
                item["channel"] = video_record.get("channel", "SCDawah Arabic")
                item["video_title_ar"] = title_ar
                item["youtube_url"] = youtube_base
                item["timestamp_url"] = f"{youtube_base}&t={int(ts_sec)}s"
                item["timestamp_seconds"] = int(ts_sec)

                chunk_units.append(item)
                all_units.append(item)
                log_extracted_unit_live(item)

            if verbose:
                if chunk_units:
                    print(f" ✅ {len(chunk_units)} Q&A found ({t_chunk}s)", flush=True)
                    for cu in chunk_units:
                        q_text = cu.get("question_ar") or cu.get("question_en") or "Untitled"
                        print(f"   │  • ❓ \"{q_text[:70]}\" [{cu.get('timestamp_formatted', '00:00')}]", flush=True)
                else:
                    print(f" ⚪ No dialectical debate in segment ({t_chunk}s)", flush=True)

        except Exception as e:
            if verbose:
                print(f" ❌ Error: {e}", flush=True)
            time.sleep(1)

    if verbose:
        print(f"   💾 Saved {len(all_units)} Q&A argument(s) for [{video_id}] to SQLite & Drive checkpoint!\n", flush=True)

    return all_units
