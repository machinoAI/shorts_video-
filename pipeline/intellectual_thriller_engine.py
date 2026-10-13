"""
The Model Verse — Intellectual Thriller Narrative Engine & Script Rewrite System (Engine 7.0)
Replaces textbook summaries and academic slide presentations with a high-tempo 4-act dopamine arc:
  Act 1: Absurd Paradox / Pattern Interrupt Hook (Beat 1, 0-3s)
  Act 2: The Villain & Bottleneck (Beat 2, 3-15s)
  Act 3: The Eureka Geometric Mechanism (Beats 3 & 4, 15-40s)
  Act 4: The Paradigm Shift / Open Loop (Beats 5 & 6, 40-50s)

Provides automated rewriting for legacy/academic drafts and strict pedagogical auditing.
"""

import os
import re
import sys
import json
from pathlib import Path
from typing import Dict, Any, List, Optional, Tuple

PROJECT_ROOT = Path(__file__).resolve().parent.parent
sys.path.append(str(PROJECT_ROOT))

import warnings
with warnings.catch_warnings():
    warnings.simplefilter("ignore", category=FutureWarning)
    try:
        import google.generativeai as genai
    except ImportError:
        genai = None

from pipeline.json_utils import robust_json_loads
from pipeline.config import CHANNEL_NAME, CHANNEL_HANDLE
try:
    from pipeline.ollama_client import OllamaClient
except ImportError:
    OllamaClient = None

# Forbidden academic / textbook lecture clichés
TEXTBOOK_LECTURE_CLICHES = [
    "today we explore", "today we'll explore", "today we look at", "today we discuss",
    "in this video", "in this paper", "in this study", "in this research",
    "the authors propose", "the authors present", "the authors introduce",
    "we propose", "we present", "we introduce", "we demonstrate",
    "let's examine", "let's dive in", "let's take a look", "welcome back",
    "this paper presents", "this study investigates", "this video explores",
    "an overview of", "a breakdown of how", "today's topic is"
]

INTELLECTUAL_THRILLER_SYSTEM_PROMPT = """
You are the Lead Creative Director and Principal Scriptwriter for '{{CHANNEL_NAME}}' ({{CHANNEL_HANDLE}}).
Your mission is to craft viral, high-retention short scripts that explain frontier AI architectures as an INTELLECTUAL THRILLER.
Style: Fireship's snappy developer realism and witty sarcasm + 3Blue1Brown's mechanical geometric intuition + Veritasium's high-stakes narrative tension.

0. FRESH SCRIPT MANDATE — NEVER PRE-DECIDE OR RECYCLE:
Every script MUST be crafted completely fresh directly from the provided paper.
NEVER reuse previous scripts, canned analogies, or pre-decided formulas.
Read the specific paper's actual claims, actual mechanics, and authentic numbers.

1. CRITICAL GROUND TRUTH REQUIREMENT:
Every single fact, problem statement, analogy, mechanism, and empirical metric MUST be derived strictly from the provided research paper title and abstract.
NEVER hallucinate or copy unrelated tools (e.g., NEVER mention Cursor, Claude, GPU compute waste, or chefs unless the paper is explicitly about them!).
- If the paper is about robotics, focus on real-world kinematics, physics simulation, or sensorimotor policies.
- If the paper is about multimodal/diffusion, focus on frame generation, denoising trajectories, or video consistency.
- If the paper is about hardware efficiency, focus on memory bandwidth, KV cache, or SRAM communication.
- If the paper is about code generation, THEN and ONLY THEN discuss coding agents, ASTs, or compiler loops.

2. REQUIRED RELATABLE DOMAIN HUMOR & DRY SARCASM:
Every script should have a spark of witty, authentic developer/researcher humor highlighting the ironic frustration of the problem:
- Robotics: The comedy of a robot that calculates million-variable kinematic trajectories in simulation but drops a spoon in the real world.
- Hardware: Paying $30,000 for server racks that spend half their time doing absolutely nothing while waiting for RAM.
- Vision / Multimodal: Giant models burning megawatts of energy to draw someone with 14 fingers.
Keep the humor dry, sharp, and grounded directly in the paper's actual friction.

STRICT CONSTRAINTS & BANNED PATTERNS:
1. BAN TEXTBOOK SUMMARIES & LECTURE INTROS:
   - NEVER start with "Today we explore...", "In this paper...", "In this video...", or "The authors propose...".
   - Treat those as immediate swipe-aways. Every word in the first 3 seconds must create intense curiosity or high-stakes friction.
2. BAN AI SLOP & BABY-TALK METAPHORS:
   - Strictly forbidden: "smart tool", "safe drawers", "open desk", "magic box", "delve into", "tapestry", "game changer".
   - AVOID UNEXPLAINED CRITICAL JARGON: NEVER use "autoregressive" (say "step-by-step" or "sequential token generation"), "softmax", "backpropagation", or "feedforward".
   - Name REAL developer tools and hardware when applicable to the paper's domain.
3. GROUNDING IN A RELEVANT PHYSICAL ANALOGY:
   - Ground the paper's core mechanical bottleneck in ONE tangible, memorable analogy tailored to its actual challenge (e.g. an assembly line bottleneck, traffic lane closures, relay race baton handoff, optical refraction, sculpting stone).

THE 4-ACT INTELLECTUAL THRILLER NARRATIVE ARC (EXACTLY 6 BEATS, 125-155 WORDS TOTAL):
- ACT 1: ABSURD PARADOX / PATTERN INTERRUPT HOOK (Beat 1, 0-3s, 12-18 words):
  * State a shocking paradox, counter-intuitive inefficiency, or core problem directly from the paper.
  * Hook the viewer in under 3 seconds before their thumb can swipe.
  * Grounded Examples across Domains (DO NOT COPY VERBATIM; WRITE SPECIFICALLY FOR THE PROVIDED PAPER):
    - Robotics: "Most humanoid robots freeze the moment they drop a tool in an unfamiliar room."
    - Hardware: "Your GPU spends up to 60% of its inference time waiting on memory bandwidth."
    - Vision: "Generating 10 seconds of consistent video used to require hundreds of wasted diffusion steps."
- ACT 2: THE VILLAIN & BOTTLENECK (Beat 2, 3-15s, 20-26 words):
  * Personify the villain / mechanical bottleneck holding back the architecture.
  * Anchor in a vivid physical analogy reflecting the paper's actual challenge.
- ACT 3: THE EUREKA GEOMETRIC MECHANISM (Beats 3 & 4, 15-40s):
  * Beat 3 (The Eureka Pivot, 20-25 words): The clean architectural breakthrough that shatters the bottleneck.
  * Beat 4 (The Technical Deep-Dive / Secret Sauce, 20-25 words): The paper's specific algorithmic trick using real engineering terms.
- ACT 4: THE PARADIGM SHIFT / OPEN LOOP (Beats 5 & 6, 40-50s):
  * Beat 5 (Empirical Victory Payoff, 18-24 words): Hard benchmark numbers proving the paradigm shift.
  * Beat 6 (The Paradigm Shift & Seamless Loop, 15-20 words): Mind-expanding takeaway that naturally loops back to Beat 1.
    Example: "Follow {{CHANNEL_NAME}} for daily deep-dives into how modern AI actually works under the hood."

JSON OUTPUT SCHEMA:
Return ONLY valid JSON matching this specification:
{
  "id": "slug_id",
  "title": "Display Title",
  "category": "mechanism_deepdive | benchmark_news | architecture_breakdown | model_showdown",
  "domain_taxonomy": "hardware_efficiency | multimodal_diffusion | robotics_tamp | neural_sae | neural_attention | neural_moe | algorithmic_search",
  "hook_tag": "SHORT PUNCHY BADGE",
  "thriller_metadata": {
    "engine_version": "7.0",
    "narrative_style": "intellectual_thriller",
    "villain_entity": "Name of villain bottleneck",
    "physical_analogy": "Description of analogy",
    "eureka_mechanism": "Name of architectural breakthrough",
    "paradigm_shift": "The new reality established by this breakthrough"
  },
  "beats": [
    {
      "beat_id": 1,
      "act": 1,
      "thriller_role": "pattern_interrupt_hook",
      "text": "spoken voiceover text under 18 words",
      "visual_focus": "chalkboard visual description",
      "highlight_words": {"key phrase": "#EF4444"},
      "svo_action": {
        "subject": "Core Entity",
        "action_verb": "disrupts",
        "direct_object": "Key Target",
        "anchor_word": "trigger",
        "semantic_role": "state_transition"
      },
      "visual_blueprint": {
        "layout": "grid_memory | split_flow | vector_flow_field | neural_activation_wave | chalkboard_code_block | horizontal_race_bars | etc",
        "title": "UPPERCASE TITLE",
        "sub": "Subtext",
        "accent_color": "#EF4444",
        "params": {}
      }
    }
  ]
}
""".replace("{{CHANNEL_NAME}}", CHANNEL_NAME).replace("{{CHANNEL_HANDLE}}", CHANNEL_HANDLE)


class IntellectualThrillerEngine:
    """
    Next-Generation Narrative Engine (Engine 7.0).
    Enforces the 4-act intellectual thriller storytelling arc and provides
    both LLM-based and deterministic script rewriting for educational AI shorts.
    """

    def __init__(self, api_key: Optional[str] = None):
        self.api_key = api_key or os.getenv("GEMINI_API_KEY") or os.getenv("GOOGLE_API_KEY")

    def audit_thriller_compliance(self, spec: Dict[str, Any]) -> Dict[str, Any]:
        """
        Audits a candidate script against the 4-Act Intellectual Thriller standard.
        Checks for:
          1. Absence of textbook lecture clichés (Beat 1 & overall)
          2. Pattern interrupt hook quality in Beat 1 (first 3 seconds)
          3. Identification of a concrete villain & physical analogy (Beat 2)
          4. Eureka mechanism & secret sauce (Beats 3 & 4)
          5. Concrete payoff numbers & open loop (Beats 5 & 6)
          6. Overall pacing and word count
        """
        beats = spec.get("beats", [])
        total_beats = len(beats)
        full_text = " ".join([b.get("text", "") for b in beats]).lower()
        
        detected_textbook_phrases = []
        for cliche in TEXTBOOK_LECTURE_CLICHES:
            if cliche in full_text:
                detected_textbook_phrases.append(cliche)

        b1_text = beats[0].get("text", "").lower() if beats else ""
        b2_text = beats[1].get("text", "").lower() if len(beats) > 1 else ""
        b5_text = beats[4].get("text", "").lower() if len(beats) > 4 else ""
        b6_text = beats[5].get("text", "").lower() if len(beats) > 5 else ""

        # Check Beat 1: Pattern Interrupt Hook
        b1_words = len(b1_text.split())
        b1_has_textbook = any(cl in b1_text for cl in TEXTBOOK_LECTURE_CLICHES)
        curiosity_triggers = [
            "waste", "wasting", "every", "nobody", "wrong", "trap", "stalling", "lying",
            "broke", "dying", "70%", "80%", "90%", "60%", "secret", "why", "shocking", "million",
            "gpu", "ai", "your", "what if", "how", "solve", "broken", "impossible",
            "struggle", "fails", "bottleneck", "paradox", "limit", "cost", "speed",
            "scale", "critical", "breakthrough", "hit a wall", "real world", "robot",
            "vision", "model", "parameter", "latency", "memory", "wall", "freeze"
        ]
        b1_has_curiosity = any(w in b1_text for w in curiosity_triggers) or ("?" in b1_text) or ("!" in b1_text)
        hook_passed = (3 <= b1_words <= 26) and (not b1_has_textbook) and b1_has_curiosity

        # Check Beat 2: The Villain & Physical Analogy
        analogy_keywords = [
            "like a", "like an", "as if", "similar to", "chef", "onion", "salt",
            "traffic", "highway", "baton", "relay", "static", "marble", "waiter",
            "cashier", "sponge", "factory", "assembly", "pipeline", "bottleneck",
            "wall", "friction", "obstacle", "challenge", "stall"
        ]
        has_analogy = any(ak in b2_text for ak in analogy_keywords) or bool(spec.get("thriller_metadata", {}).get("physical_analogy"))
        has_villain = any(w in b2_text for w in [
            "bottleneck", "why?", "because", "wait", "stall", "sequential", "memory",
            "wall", "stuck", "problem", "fails", "limit", "cost", "struggle",
            "friction", "obstacle", "slow", "freeze", "error"
        ]) or bool(spec.get("thriller_metadata", {}).get("villain_entity"))
        act2_passed = has_analogy or has_villain

        # Check Beat 5: Empirical Payoff Numbers
        has_payoff_numbers = any(c in b5_text for c in [
            "x", "%", "faster", "speedup", "tflops", "benchmark", "accuracy", "zero",
            "gain", "gains", "drop", "score", "proven", "result", "beats", "sota", "state-of-the-art"
        ])

        # Check Beat 6: Loop / Follow Outro
        has_outro_loop = any(w in b6_text for w in ["follow", "the model verse", CHANNEL_NAME.lower(), "daily", "under the hood", "next"])

        # Compute Thriller Score
        score = 8.5
        if detected_textbook_phrases:
            score -= 3.0 * len(detected_textbook_phrases)
        if not hook_passed:
            score -= 2.0
        if not act2_passed:
            score -= 1.5
        if not has_payoff_numbers:
            score -= 1.0
        if not has_outro_loop:
            score -= 0.5
        if total_beats == 6:
            score += 0.5

        score = max(1.0, min(10.0, round(score, 1)))
        passed = score >= 8.0 and not detected_textbook_phrases and hook_passed

        return {
            "score": score,
            "passed": passed,
            "detected_textbook_phrases": detected_textbook_phrases,
            "hook_passed": hook_passed,
            "act2_villain_passed": act2_passed,
            "act4_payoff_passed": has_payoff_numbers,
            "b1_word_count": b1_words,
            "total_beats": total_beats,
            "verdict": "APPROVED: High-tempo Intellectual Thriller" if passed else f"REJECTED: Needs thriller rewrite (Score {score}/10)"
        }

    def rewrite_script_to_thriller(
        self,
        spec: Dict[str, Any],
        paper_meta: Optional[Dict[str, Any]] = None,
        use_llm: bool = True
    ) -> Dict[str, Any]:
        """
        Rewrites a script spec into the 4-Act Intellectual Thriller narrative model.
        Uses Ollama Cloud or Gemini if available; otherwise applies deterministic transformation
        strictly grounded in paper metadata.
        """
        title = spec.get("title", "AI Architecture Breakdown")
        topic = (paper_meta.get("title") if paper_meta else None) or title
        category = spec.get("category", "mechanism_deepdive")
        domain = spec.get("domain_taxonomy", "hardware_efficiency")

        if use_llm:
            prompt_input = {
                "paper_title": topic,
                "category": category,
                "domain": domain,
                "existing_beats": [b.get("text", "") for b in spec.get("beats", [])],
                "abstract": (paper_meta.get("abstract") if paper_meta else None) or "",
            }

            user_prompt = f"""
REWRITE THIS SCRIPT AS A HIGH-TEMPO 4-ACT INTELLECTUAL THRILLER (GROUND TRUTH ONLY):
Input Specification:
{json.dumps(prompt_input, indent=2)}

CRITICAL GROUND TRUTH RULES:
1. Base ALL facts, hooks, villains, and metrics STRICTLY on this specific paper ({topic}).
2. NEVER mention Cursor, Claude, or GPU compute waste unless this paper is explicitly about them!
3. If the paper is about robotics, focus on robotics and physical simulation. If about diffusion, focus on generative visual latency and denoising. If about hardware, focus on memory bandwidth and compute walls.
4. Eradicate all textbook lecture introductions ("Today we explore...").
5. Beat 1 MUST be a 0-3s (under 18 words) pattern interrupt hook derived from the paper's core challenge.
6. Beat 2 MUST establish the villain & mechanical bottleneck with ONE intuitive physical analogy.
7. Beats 3 & 4 MUST reveal the eureka mechanism and technical secret sauce from the paper.
8. Beat 5 MUST deliver concrete empirical payoff numbers from the paper.
9. Beat 6 MUST be a crisp outro looping back to Beat 1.
10. Return exactly 6 beats adhering to the required JSON schema.
"""
            use_ollama = (os.getenv("LLM_PROVIDER", "").lower() == "ollama") or (not self.api_key)
            if use_ollama and OllamaClient:
                try:
                    ollama = OllamaClient()
                    res = ollama.generate_completion(
                        prompt=user_prompt,
                        system=INTELLECTUAL_THRILLER_SYSTEM_PROMPT,
                        format="json",
                    )
                    parsed = res.to_dict() if hasattr(res, "to_dict") else dict(res)
                    if parsed and "beats" in parsed and len(parsed["beats"]) >= 5:
                        return self._merge_thriller_updates(spec, parsed)
                except Exception:
                    pass

            if self.api_key and genai and not use_ollama:
                candidate_models = [
                    os.getenv("GEMINI_MODEL_NAME", "gemini-flash-latest"),
                    "gemini-3.1-flash-lite",
                    "gemini-flash-latest",
                    "gemini-2.5-flash",
                    "gemini-2.0-flash"
                ]
                for m_name in candidate_models:
                    try:
                        model = genai.GenerativeModel(
                            m_name,
                            system_instruction=INTELLECTUAL_THRILLER_SYSTEM_PROMPT,
                            generation_config={"response_mime_type": "application/json", "temperature": 0.3}
                        )
                        resp = model.generate_content(user_prompt)
                        if resp and resp.text:
                            parsed = robust_json_loads(resp.text)
                            if parsed and "beats" in parsed and len(parsed["beats"]) >= 5:
                                return self._merge_thriller_updates(spec, parsed)
                    except Exception as e:
                        err_msg = str(e)
                        if "ResourceExhausted" in err_msg or "429" in err_msg:
                            break
                        continue

            # Fallback to Ollama if Gemini was attempted but failed
            if not use_ollama and OllamaClient:
                try:
                    ollama = OllamaClient()
                    res = ollama.generate_completion(
                        prompt=user_prompt,
                        system=INTELLECTUAL_THRILLER_SYSTEM_PROMPT,
                        format="json",
                    )
                    parsed = res.to_dict() if hasattr(res, "to_dict") else dict(res)
                    if parsed and "beats" in parsed and len(parsed["beats"]) >= 5:
                        return self._merge_thriller_updates(spec, parsed)
                except Exception:
                    pass

        # 2. Resilient Deterministic Rewrite strictly grounded in paper truth
        return self._apply_deterministic_thriller_rewrite(spec, paper_meta)

    def _merge_thriller_updates(self, original_spec: Dict[str, Any], rewritten: Dict[str, Any]) -> Dict[str, Any]:
        """Merges rewritten thriller beats while preserving custom layouts, code snippets, and SVGs."""
        new_spec = dict(original_spec)
        new_spec["thriller_metadata"] = rewritten.get("thriller_metadata", {
            "engine_version": "7.0",
            "narrative_style": "intellectual_thriller"
        })

        if "hook_tag" in rewritten:
            new_spec["hook_tag"] = rewritten["hook_tag"]

        orig_beats = new_spec.get("beats", [])
        new_beats = rewritten.get("beats", [])

        # Ensure exactly 6 beats
        merged_beats = []
        for i in range(min(len(orig_beats), len(new_beats))):
            ob = dict(orig_beats[i])
            nb = new_beats[i]

            ob["text"] = nb.get("text", ob.get("text", ""))
            ob["thriller_role"] = nb.get("thriller_role", self._get_default_thriller_role(i + 1))
            ob["act"] = self._get_act_number(i + 1)
            
            if nb.get("visual_focus"):
                ob["visual_focus"] = nb["visual_focus"]
            if nb.get("highlight_words"):
                ob["highlight_words"] = nb["highlight_words"]
            if nb.get("svo_action"):
                ob["svo_action"] = nb["svo_action"]

            # Merge blueprint titles if available
            if nb.get("visual_blueprint") and ob.get("visual_blueprint"):
                nb_bp = nb["visual_blueprint"]
                if nb_bp.get("title"):
                    ob["visual_blueprint"]["title"] = nb_bp["title"]
                if nb_bp.get("sub"):
                    ob["visual_blueprint"]["sub"] = nb_bp["sub"]
            elif nb.get("visual_blueprint") and not ob.get("visual_blueprint"):
                ob["visual_blueprint"] = nb["visual_blueprint"]

            merged_beats.append(ob)

        # Pad up to 6 beats if needed
        while len(merged_beats) < 6:
            bid = len(merged_beats) + 1
            merged_beats.append(self._generate_fallback_beat(bid, new_spec.get("title", "AI Architecture")))

        new_spec["beats"] = merged_beats
        return new_spec

    def _apply_deterministic_thriller_rewrite(
        self,
        spec: Dict[str, Any],
        paper_meta: Optional[Dict[str, Any]] = None
    ) -> Dict[str, Any]:
        """
        Deterministic, rule-based transformation:
        Eliminates textbook openings, preserves authentic domain topics,
        structures the villain and analogy in Beat 2, and validates thriller roles.
        NEVER injects fabricated tools, Cursor/Claude, or universal chef analogies.
        """
        updated = dict(spec)
        topic = (paper_meta.get("title") if paper_meta else None) or updated.get("title", "Modern AI Architecture")
        clean_topic = re.sub(r'[^a-zA-Z0-9\s\-:]', '', topic).strip()
        beats = updated.get("beats", [])

        # If beats empty or incomplete, initialize standard 6-beat template
        if len(beats) < 6:
            beats = [self._generate_fallback_beat(i + 1, clean_topic, paper_meta) for i in range(6)]

        # --- ACT 1: Transform Beat 1 into Pattern Interrupt Hook ---
        b1 = beats[0]
        b1_raw = b1.get("text", "").strip()
        # Remove any textbook prefixes
        for cl in TEXTBOOK_LECTURE_CLICHES:
            if b1_raw.lower().startswith(cl):
                b1_raw = b1_raw[len(cl):].lstrip(" :,.-")

        # If Beat 1 was a dry summary or stripped down, ground it in the real topic
        if not b1_raw or len(b1_raw.split()) < 3:
            b1["text"] = f"Why are top AI researchers paying attention to {clean_topic[:36]}?"
        else:
            b1["text"] = b1_raw

        b1["thriller_role"] = "pattern_interrupt_hook"
        b1["act"] = 1
        if "highlight_words" not in b1 or not b1["highlight_words"]:
            words = b1["text"].split()
            first_key = words[0] if words else "AI"
            b1["highlight_words"] = {first_key: "#EF4444"}

        # --- ACT 2: Transform Beat 2 into Villain & Bottleneck ---
        b2 = beats[1]
        b2_raw = b2.get("text", "").strip()
        for cl in TEXTBOOK_LECTURE_CLICHES:
            if b2_raw.lower().startswith(cl):
                b2_raw = b2_raw[len(cl):].lstrip(" :,.-")

        if not b2_raw or len(b2_raw.split()) < 3:
            b2["text"] = f"The bottleneck? Traditional systems hit a scaling wall when handling complex workloads without massive friction."
        else:
            b2["text"] = b2_raw

        b2["thriller_role"] = "villain_bottleneck"
        b2["act"] = 2
        if "highlight_words" not in b2 or not b2["highlight_words"]:
            b2["highlight_words"] = {"bottleneck": "#F59E0B"}

        # --- ACT 3: Transform Beats 3 & 4 into Eureka Mechanism & Secret Sauce ---
        b3 = beats[2]
        b3_raw = b3.get("text", "").strip()
        for cl in TEXTBOOK_LECTURE_CLICHES:
            if cl in b3_raw.lower():
                pattern = re.compile(re.escape(cl), re.IGNORECASE)
                b3_raw = pattern.sub(f"Enter {clean_topic[:28]}:", b3_raw)
        b3["text"] = b3_raw.strip() or f"Enter {clean_topic[:28]}: an architecture built from the ground up to eliminate this stall."
        b3["thriller_role"] = "eureka_mechanism"
        b3["act"] = 3

        b4 = beats[3]
        b4_raw = b4.get("text", "").strip()
        for cl in TEXTBOOK_LECTURE_CLICHES:
            if cl in b4_raw.lower():
                pattern = re.compile(re.escape(cl), re.IGNORECASE)
                b4_raw = pattern.sub("Under the hood,", b4_raw)
        b4["text"] = b4_raw.strip() or "Under the hood, the system coordinates parallel execution without blocking critical paths."
        b4["thriller_role"] = "technical_secret_sauce"
        b4["act"] = 3

        # --- ACT 4: Transform Beats 5 & 6 into Paradigm Shift Payoff & Open Loop ---
        b5 = beats[4]
        b5_raw = b5.get("text", "").strip()
        for cl in TEXTBOOK_LECTURE_CLICHES:
            if cl in b5_raw.lower():
                pattern = re.compile(re.escape(cl), re.IGNORECASE)
                b5_raw = pattern.sub("Empirically,", b5_raw)
        if not b5_raw or len(b5_raw.split()) < 3:
            b5["text"] = f"The result? Proven empirical gains and state-of-the-art benchmarks on {clean_topic[:24]}."
        else:
            b5["text"] = b5_raw
        b5["thriller_role"] = "empirical_payoff"
        b5["act"] = 4

        b6 = beats[5]
        b6_raw = b6.get("text", "").strip()
        if not b6_raw or len(b6_raw.split()) < 3:
            b6["text"] = f"Follow {CHANNEL_NAME} for daily deep-dives into how modern AI actually works under the hood."
        else:
            b6["text"] = b6_raw
        b6["thriller_role"] = "open_loop_outro"
        b6["act"] = 4
        if "highlight_words" not in b6 or not b6["highlight_words"]:
            b6["highlight_words"] = {CHANNEL_NAME: "#34D399"}

        # --- Sanitize any lingering textbook clichés across all beats ---
        for b in beats:
            b_text = b.get("text", "")
            for cl in TEXTBOOK_LECTURE_CLICHES:
                if cl in b_text.lower():
                    pattern = re.compile(re.escape(cl), re.IGNORECASE)
                    b_text = pattern.sub("this breakthrough introduces", b_text)
            b["text"] = b_text.strip()

        updated["beats"] = beats
        updated["thriller_metadata"] = {
            "engine_version": "7.0",
            "narrative_style": "intellectual_thriller",
            "acts": {
                "act_1_hook": {"beat": 1, "role": "pattern_interrupt_hook"},
                "act_2_villain": {"beat": 2, "role": "villain_bottleneck"},
                "act_3_eureka": {"beats": [3, 4], "role": "eureka_mechanism"},
                "act_4_paradigm_shift": {"beats": [5, 6], "role": "paradigm_shift_open_loop"}
            }
        }
        return updated

    def _get_act_number(self, beat_id: int) -> int:
        if beat_id == 1:
            return 1
        elif beat_id == 2:
            return 2
        elif beat_id in (3, 4):
            return 3
        return 4

    def _get_default_thriller_role(self, beat_id: int) -> str:
        roles = {
            1: "pattern_interrupt_hook",
            2: "villain_bottleneck",
            3: "eureka_mechanism",
            4: "technical_secret_sauce",
            5: "empirical_payoff",
            6: "open_loop_outro"
        }
        return roles.get(beat_id, "narrative_beat")

    def _generate_fallback_beat(self, beat_id: int, topic: str, paper_meta: Optional[Dict[str, Any]] = None) -> Dict[str, Any]:
        clean_topic = topic[:30] if topic else "Modern AI"
        abstract_text = ""
        cat = ""
        if paper_meta and isinstance(paper_meta, dict):
            abstract_text = (paper_meta.get("abstract") or paper_meta.get("summary") or "").strip()
            cat = (paper_meta.get("category") or "").lower()

        sentences = [s.strip() for s in re.split(r"(?<=[.!?])\s+", abstract_text) if len(s.strip()) > 15]

        if len(sentences) >= 4:
            s0 = sentences[0].rstrip(".?! ")
            s1 = sentences[1].rstrip(".?! ")
            s2 = sentences[2].rstrip(".?! ")
            s3 = sentences[3].rstrip(".?! ")
            s4 = sentences[4].rstrip(".?! ") if len(sentences) >= 5 else f"Proven empirical gains across {clean_topic}"

            t1 = f"Why are top AI researchers calling {clean_topic} a breakthrough? Because {s0[0].lower() + s0[1:]}." if not any(w in s0.lower() for w in ("you", "your")) else s0 + "."
            t2 = f"The core bottleneck? {s1}."
            t3 = f"Enter {clean_topic}: {s2[0].lower() + s2[1:]}."
            t4 = f"Under the hood, {s3[0].lower() + s3[1:]}."
            t5 = f"The result? {s4}."
            t6 = f"Follow {CHANNEL_NAME} for daily deep-dives into how modern AI actually works under the hood."

            defaults = {
                1: {
                    "beat_id": 1, "act": 1, "thriller_role": "pattern_interrupt_hook",
                    "text": t1,
                    "visual_focus": f"System architecture diagram illustrating {clean_topic}.",
                    "highlight_words": {clean_topic: "#38BDF8"},
                    "svo_action": {"subject": clean_topic, "action_verb": "disrupts", "direct_object": "Standard Paradigms", "anchor_word": clean_topic.split()[0], "semantic_role": "state_transition"},
                    "visual_blueprint": {"layout": "grid_memory", "title": clean_topic.upper(), "sub": "Core Premise", "accent_color": "#38BDF8", "params": {}}
                },
                2: {
                    "beat_id": 2, "act": 2, "thriller_role": "villain_bottleneck",
                    "text": t2,
                    "visual_focus": "Bottleneck diagram highlighting resource contention and execution stall.",
                    "highlight_words": {"bottleneck": "#EF4444"},
                    "svo_action": {"subject": "System Bottleneck", "action_verb": "stalls", "direct_object": "Pipeline Flow", "anchor_word": "bottleneck", "semantic_role": "bottleneck"},
                    "visual_blueprint": {"layout": "vector_flow_field", "title": "SYSTEM BOTTLENECK", "sub": "Resource Contention", "accent_color": "#EF4444", "params": {}}
                },
                3: {
                    "beat_id": 3, "act": 3, "thriller_role": "eureka_mechanism",
                    "text": t3,
                    "visual_focus": "Parallel pipeline splitting heavy operations away from the critical execution path.",
                    "highlight_words": {clean_topic: "#10B981"},
                    "svo_action": {"subject": clean_topic, "action_verb": "bypasses", "direct_object": "Execution Bottleneck", "anchor_word": "Enter", "semantic_role": "mechanism"},
                    "visual_blueprint": {"layout": "split_flow", "title": "PARALLEL PIPELINE", "sub": "Decoupled Execution", "accent_color": "#10B981", "params": {}}
                },
                4: {
                    "beat_id": 4, "act": 3, "thriller_role": "technical_secret_sauce",
                    "text": t4,
                    "visual_focus": "Low-level coordinate graph demonstrating execution flow without idle states.",
                    "highlight_words": {"Under the hood": "#38BDF8"},
                    "svo_action": {"subject": "Execution Engine", "action_verb": "coordinates", "direct_object": "Task Flow", "anchor_word": "hood", "semantic_role": "innovation"},
                    "visual_blueprint": {"layout": "chalkboard_code_block", "title": "EXECUTION MECHANICS", "sub": "Algorithmic Coordination", "accent_color": "#38BDF8", "params": {}}
                },
                5: {
                    "beat_id": 5, "act": 4, "thriller_role": "empirical_payoff",
                    "text": t5,
                    "visual_focus": "Comparative benchmark race bars showing massive performance gains.",
                    "highlight_words": {"result": "#10B981"},
                    "svo_action": {"subject": clean_topic, "action_verb": "delivers", "direct_object": "Benchmark Gains", "anchor_word": "result", "semantic_role": "victory"},
                    "visual_blueprint": {"layout": "horizontal_race_bars", "title": "BENCHMARK PERFORMANCE", "sub": "Empirical Gains", "accent_color": "#10B981", "params": {}}
                },
                6: {
                    "beat_id": 6, "act": 4, "thriller_role": "open_loop_outro",
                    "text": t6,
                    "visual_focus": f"Chalkboard brand logo with glowing cyan rings, subscribe badge, and loop transition for {CHANNEL_NAME}.",
                    "highlight_words": {CHANNEL_NAME: "#34D399"},
                    "svo_action": {"subject": "Viewer", "action_verb": "follows", "direct_object": CHANNEL_NAME, "anchor_word": "daily", "semantic_role": "loop"},
                    "visual_blueprint": {"layout": "neural_activation_wave", "title": CHANNEL_NAME.upper(), "sub": "Daily AI Research Breakdowns", "accent_color": "#34D399", "params": {}}
                }
            }
            return defaults.get(beat_id, defaults[1])

        if cat == "developer_perks":
            defaults = {
                1: {
                    "beat_id": 1, "act": 1, "thriller_role": "pattern_interrupt_hook",
                    "text": f"Stop paying full price for AI tokens before checking out {clean_topic}.",
                    "visual_focus": "Program grant tiers and token subsidization badge.",
                    "highlight_words": {clean_topic: "#38BDF8", "full price": "#EF4444"},
                    "svo_action": {"subject": "Developers", "action_verb": "claim", "direct_object": "API Grants", "anchor_word": "tokens", "semantic_role": "state_transition"},
                    "visual_blueprint": {"layout": "catalog_routing", "title": "DEVELOPER PROGRAM", "sub": "Subsidized Model Access", "accent_color": "#38BDF8", "params": {}}
                },
                2: {
                    "beat_id": 2, "act": 2, "thriller_role": "villain_bottleneck",
                    "text": "The villain? Skyrocketing inference and token expenses that deplete startup runways before launch.",
                    "visual_focus": "Burn rate chart showing capital exhaustion on token usage.",
                    "highlight_words": {"deplete": "#EF4444", "runways": "#F59E0B"},
                    "svo_action": {"subject": "API Costs", "action_verb": "drains", "direct_object": "Engineering Runway", "anchor_word": "deplete", "semantic_role": "bottleneck"},
                    "visual_blueprint": {"layout": "barrier_separation", "title": "API COST BOTTLENECK", "sub": "Inference Spend Pressure", "accent_color": "#EF4444", "params": {}}
                },
                3: {
                    "beat_id": 3, "act": 3, "thriller_role": "eureka_mechanism",
                    "text": f"Enter {clean_topic}. It unlocks dedicated credits and foundation model subsidies.",
                    "visual_focus": f"Grant tier dashboard highlighting compute subsidies via {clean_topic}.",
                    "highlight_words": {clean_topic: "#10B981", "dedicated credits": "#38BDF8"},
                    "svo_action": {"subject": clean_topic, "action_verb": "unlocks", "direct_object": "Free Compute", "anchor_word": "credits", "semantic_role": "mechanism"},
                    "visual_blueprint": {"layout": "split_flow", "title": "SUBSIDIZED COMPUTE", "sub": "Foundation Model Credits", "accent_color": "#10B981", "params": {}}
                },
                4: {
                    "beat_id": 4, "act": 3, "thriller_role": "technical_secret_sauce",
                    "text": "Under the hood, qualifying teams bypass expensive bills with verified application steps.",
                    "visual_focus": "Step-by-step application walkthrough showing instant verification.",
                    "highlight_words": {"bypass": "#34D399", "application steps": "#38BDF8"},
                    "svo_action": {"subject": "Application Portal", "action_verb": "verifies", "direct_object": "Credentials", "anchor_word": "bypass", "semantic_role": "innovation"},
                    "visual_blueprint": {"layout": "chalkboard_code_block", "title": "VERIFICATION STEPS", "sub": "Application & Approval Process", "accent_color": "#38BDF8", "params": {}}
                },
                5: {
                    "beat_id": 5, "act": 4, "thriller_role": "empirical_payoff",
                    "text": f"The result? Tens of thousands in compute savings to ship production models faster.",
                    "visual_focus": "Capital savings comparison showing months of extended runway.",
                    "highlight_words": {"compute savings": "#10B981"},
                    "svo_action": {"subject": clean_topic, "action_verb": "saves", "direct_object": "Engineering Capital", "anchor_word": "savings", "semantic_role": "victory"},
                    "visual_blueprint": {"layout": "horizontal_race_bars", "title": "CAPITAL PRESERVATION", "sub": "Total Dollar Value Unlocked", "accent_color": "#10B981", "params": {}}
                },
                6: {
                    "beat_id": 6, "act": 4, "thriller_role": "open_loop_outro",
                    "text": f"Follow {CHANNEL_NAME} for daily updates on free developer perks, tools, and frontier AI models.",
                    "visual_focus": f"Chalkboard brand signature with subscribe indicator for {CHANNEL_NAME}.",
                    "highlight_words": {CHANNEL_NAME: "#34D399"},
                    "svo_action": {"subject": CHANNEL_NAME, "action_verb": "curates", "direct_object": "Developer Perks", "anchor_word": "Perks", "semantic_role": "loop"},
                    "visual_blueprint": {"layout": "neural_activation_wave", "title": CHANNEL_NAME.upper(), "sub": "Daily Developer Perks & Research", "accent_color": "#34D399", "params": {}}
                }
            }
            return defaults.get(beat_id, defaults[1])

        defaults = {
            1: {
                "beat_id": 1, "act": 1, "thriller_role": "pattern_interrupt_hook",
                "text": f"Why are top AI researchers calling {clean_topic} a fundamental breakthrough?",
                "visual_focus": "System architecture diagram illustrating the core mechanical tension.",
                "highlight_words": {clean_topic: "#38BDF8", "breakthrough": "#EF4444"},
                "svo_action": {"subject": clean_topic, "action_verb": "disrupts", "direct_object": "Standard Paradigms", "anchor_word": "breakthrough", "semantic_role": "state_transition"},
                "visual_blueprint": {"layout": "grid_memory", "title": "ARCHITECTURAL BOTTLENECK", "sub": "Compute units idle waiting for data", "accent_color": "#EF4444", "params": {}}
            },
            2: {
                "beat_id": 2, "act": 2, "thriller_role": "villain_bottleneck",
                "text": "The bottleneck? Existing approaches stall when scaling up, hitting severe latency and resource barriers.",
                "visual_focus": "Bottleneck diagram highlighting the scaling wall and resource stall.",
                "highlight_words": {"stall": "#EF4444", "resource barriers": "#F59E0B"},
                "svo_action": {"subject": "Scaling Wall", "action_verb": "stalls", "direct_object": "System Pipeline", "anchor_word": "stall", "semantic_role": "bottleneck"},
                "visual_blueprint": {"layout": "vector_flow_field", "title": "SYSTEM BOTTLENECK", "sub": "Resource contention halts throughput", "accent_color": "#F59E0B", "params": {}}
            },
            3: {
                "beat_id": 3, "act": 3, "thriller_role": "eureka_mechanism",
                "text": f"Enter {clean_topic}. It bypasses these limitations with a decoupled, high-throughput pipeline.",
                "visual_focus": "Parallel pipeline bypassing standard execution walls.",
                "highlight_words": {clean_topic: "#10B981", "bypasses": "#38BDF8"},
                "svo_action": {"subject": clean_topic, "action_verb": "bypasses", "direct_object": "Execution Bottleneck", "anchor_word": "bypasses", "semantic_role": "mechanism"},
                "visual_blueprint": {"layout": "split_flow", "title": "PARALLEL PIPELINE", "sub": "Decoupled execution paths", "accent_color": "#10B981", "params": {}}
            },
            4: {
                "beat_id": 4, "act": 3, "thriller_role": "technical_secret_sauce",
                "text": "Under the hood, the system coordinates execution asynchronously, eliminating idle wait states entirely.",
                "visual_focus": "Asynchronous coordinate graph demonstrating zero idle wait states.",
                "highlight_words": {"asynchronously": "#38BDF8", "zero idle": "#10B981"},
                "svo_action": {"subject": "Asynchronous Engine", "action_verb": "coordinates", "direct_object": "Task Flow", "anchor_word": "asynchronously", "semantic_role": "innovation"},
                "visual_blueprint": {"layout": "chalkboard_code_block", "title": "ASYNC COORDINATION", "sub": "Zero-stall execution kernel", "accent_color": "#38BDF8", "params": {}}
            },
            5: {
                "beat_id": 5, "act": 4, "thriller_role": "empirical_payoff",
                "text": f"The result? Dramatic benchmark gains across standard workloads with zero loss in fidelity.",
                "visual_focus": "Comparative benchmark race bars showing massive performance gains.",
                "highlight_words": {"benchmark gains": "#10B981", "zero loss": "#38BDF8"},
                "svo_action": {"subject": "Benchmark Metric", "action_verb": "accelerates", "direct_object": "Performance", "anchor_word": "gains", "semantic_role": "victory"},
                "visual_blueprint": {"layout": "horizontal_race_bars", "title": "BENCHMARK PERFORMANCE", "sub": "Substantial efficiency and accuracy gains", "accent_color": "#10B981", "params": {}}
            },
            6: {
                "beat_id": 6, "act": 4, "thriller_role": "open_loop_outro",
                "text": f"Follow {CHANNEL_NAME} for daily deep-dives into how modern AI actually works under the hood.",
                "visual_focus": f"Chalkboard brand logo with glowing cyan rings, subscribe badge, and loop transition for {CHANNEL_NAME}.",
                "highlight_words": {CHANNEL_NAME: "#34D399"},
                "svo_action": {"subject": "Viewer", "action_verb": "follows", "direct_object": CHANNEL_NAME, "anchor_word": "daily", "semantic_role": "loop"},
                "visual_blueprint": {"layout": "neural_activation_wave", "title": CHANNEL_NAME.upper(), "sub": "Daily AI Architecture & Research Breakdowns", "accent_color": "#34D399", "params": {}}
            }
        }
        return defaults.get(beat_id, defaults[1])


# Global Singleton Instance
intellectual_thriller_engine = IntellectualThrillerEngine()
