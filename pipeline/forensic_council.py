"""
==============================================================================
ScamShield-VN: 5-Agent Multi-LLM Forensic Council Orchestrator
==============================================================================
Author: ScamShield Core Research & Engineering Team
Description:
    Implements the 5-Agent Forensic Council for Tier-2 Deep Message Analysis:
    1. Cyber Threat & Malicious URL Inspector (Gemini Flash / GPT-4o-mini)
    2. Social Engineering & Urgency Profiler (Gemini Pro / Claude Haiku)
    3. Vietnamese Linguistic & Teencode Analyst (Qwen 2.5 / DeepSeek)
    4. Banking & Financial Protocol Verifier (Claude Haiku / GPT-4o-mini)
    5. Public Defender / Anti-False-Positive Advocate (GPT-4o-mini / Gemini Flash)

    Features:
    - Asynchronous concurrent execution (asyncio.gather / as_completed)
    - Fast-Path Early-Exit on supermajority (4-1 or 5-0)
    - Circuit Breaker & Standby Priority Chain fallback (HTTP 429 resilience)
    - Weighted Borda consensus with Public Defender false-alarm protection
==============================================================================
"""

import os
import time
import json
import logging
import asyncio
from typing import Dict, List, Optional, Any, Tuple
import yaml
import requests
from dotenv import load_dotenv

# Auto-load environment variables from project root
load_dotenv(os.path.join(os.path.dirname(os.path.dirname(os.path.abspath(__file__))), ".env"))

logger = logging.getLogger("ScamShield.ForensicCouncil")
if not logger.handlers:
    handler = logging.StreamHandler()
    formatter = logging.Formatter(
        "[%(asctime)s] [%(levelname)s] [%(name)s]: %(message)s", 
        datefmt="%H:%M:%S"
    )
    handler.setFormatter(formatter)
    logger.addHandler(handler)
    logger.setLevel(logging.INFO)


class CircuitBreaker:
    """Manages failure counts and cooldown periods per model provider."""
    def __init__(self, failure_threshold: int = 3, cooldown_seconds: int = 300):
        self.failure_threshold = failure_threshold
        self.cooldown_seconds = cooldown_seconds
        self.consecutive_failures: Dict[str, int] = {}
        self.cooldown_until: Dict[str, float] = {}

    def is_available(self, model_name: str) -> bool:
        now = time.time()
        if self.cooldown_until.get(model_name, 0) > now:
            return False
        return True

    def record_success(self, model_name: str):
        self.consecutive_failures[model_name] = 0
        if model_name in self.cooldown_until:
            del self.cooldown_until[model_name]

    def record_failure(self, model_name: str):
        fails = self.consecutive_failures.get(model_name, 0) + 1
        self.consecutive_failures[model_name] = fails
        if fails >= self.failure_threshold:
            self.cooldown_until[model_name] = time.time() + self.cooldown_seconds
            logger.warning(
                f"CircuitBreaker OPEN for '{model_name}'. Cooldown {self.cooldown_seconds}s "
                f"due to {fails} consecutive errors."
            )


class ForensicCouncil:
    """
    Tier-2 Multi-LLM Forensic Council Orchestrator.
    Supports dynamic role ablation (3-Agent vs 5-Agent) and standardized 3-label consensus:
    - SCAM-RISK
    - LOW-RISK
    - UNKNOWN
    """

    def __init__(self, config_path: Optional[str] = None, active_roles: Optional[List[str]] = None):
        base_dir = os.path.dirname(os.path.dirname(os.path.abspath(__file__)))
        self.config_path = config_path or os.path.join(base_dir, "config", "council_registry.yaml")
        self.config = self._load_config()
        self.specialists = self.config.get("specialists", {})
        self.active_roles = active_roles
        self.consensus_rules = self.config.get("consensus_rules", {})
        self.cb_cfg = self.config.get("circuit_breaker", {})
        self.circuit_breaker = CircuitBreaker(
            failure_threshold=self.cb_cfg.get("failure_threshold", 3),
            cooldown_seconds=self.cb_cfg.get("cooldown_seconds", 300),
        )

        # API Keys & URLs
        self.gemini_api_key = os.getenv("GEMINI_API_KEY") or os.getenv("GOOGLE_API_KEY") or ""
        self.groq_api_key = os.getenv("GROQ_API_KEY") or ""
        self.openai_api_key = os.getenv("OPENAI_API_KEY") or ""
        self.anthropic_api_key = os.getenv("ANTHROPIC_API_KEY") or ""
        self.vibi_base_url = os.getenv("VIBI_BASE_URL", "https://vibi.top/v1")

        logger.info(
            f"ForensicCouncil initialized with {len(self.specialists)} specialists. "
            f"Early-Exit = {self.config.get('council_metadata', {}).get('early_exit_enabled', True)}"
        )

    def _load_config(self) -> Dict[str, Any]:
        try:
            with open(self.config_path, "r", encoding="utf-8") as f:
                return yaml.safe_load(f)
        except Exception as e:
            logger.error(f"Failed to load council config at {self.config_path}: {e}")
            return {}

    async def _call_gemini_api(self, model: str, prompt: str, system_prompt: str) -> Dict[str, Any]:
        """Calls Google Gemini REST API securely via x-goog-api-key header."""
        if not self.gemini_api_key:
            raise ValueError("GEMINI_API_KEY missing")

        api_model = model.lower()
        # Enforce Rule 5: NEVER call Gemini < 3.5
        if any(api_model.startswith(p) for p in ["gemini-1.", "gemini-2."]):
            logger.warning(f"Guardrail triggered: Rejecting '{api_model}' (< Gemini 3.5). Promoting to gemini-3.5-flash-lite.")
            api_model = "gemini-3.5-flash-lite"
        elif "3.5" in api_model and "lite" in api_model:
            api_model = "gemini-3.5-flash-lite"
        elif "3.8" in api_model:
            api_model = "gemini-3.8-flash"
        elif "3.5" in api_model:
            api_model = "gemini-3.5-flash"
        elif "gemini" in api_model:
            api_model = "gemini-3.5-flash-lite"

        url = f"https://generativelanguage.googleapis.com/v1beta/models/{api_model}:generateContent"
        headers = {
            "x-goog-api-key": self.gemini_api_key,
            "Content-Type": "application/json"
        }
        payload = {
            "contents": [{"parts": [{"text": prompt}]}],
            "systemInstruction": {"parts": [{"text": system_prompt}]},
            "generationConfig": {
                "temperature": 0.1,
                "responseMimeType": "application/json",
            }
        }

        loop = asyncio.get_event_loop()
        def _sync_post():
            resp = requests.post(url, headers=headers, json=payload, timeout=15.0)
            resp.raise_for_status()
            return resp.json()

        data = await loop.run_in_executor(None, _sync_post)
        raw_text = data["candidates"][0]["content"]["parts"][0]["text"].strip()
        if raw_text.startswith("```json"):
            raw_text = raw_text.replace("```json", "").replace("```", "").strip()
        elif raw_text.startswith("```"):
            raw_text = raw_text.replace("```", "").strip()
        return json.loads(raw_text)

    async def _call_vibi_api(self, model: str, prompt: str, system_prompt: str) -> Dict[str, Any]:
        """Calls vibi.top OpenAI-compatible proxy for GPT and Claude models."""
        key = self.openai_api_key if ("gpt" in model or "sol" in model) else (self.anthropic_api_key or self.openai_api_key)
        if not key:
            raise ValueError("VIBI / OPENAI API KEY missing")

        url = f"{self.vibi_base_url.rstrip('/')}/chat/completions"
        headers = {
            "Authorization": f"Bearer {key}",
            "Content-Type": "application/json"
        }
        payload = {
            "model": model,
            "messages": [
                {"role": "system", "content": system_prompt},
                {"role": "user", "content": prompt}
            ],
            "temperature": 0.1,
            "stream": False
        }

        loop = asyncio.get_event_loop()
        def _sync_post():
            resp = requests.post(url, headers=headers, json=payload, timeout=25.0)
            resp.raise_for_status()
            return resp.json()

        data = await loop.run_in_executor(None, _sync_post)
        raw_text = data["choices"][0]["message"]["content"].strip()
        if raw_text.startswith("```json"):
            raw_text = raw_text.replace("```json", "").replace("```", "").strip()
        elif raw_text.startswith("```"):
            raw_text = raw_text.replace("```", "").strip()
        try:
            return json.loads(raw_text)
        except Exception:
            # Fallback regex parsing if JSON format is broken
            vote = "SCAM" if "SCAM" in raw_text.upper() else "HAM"
            return {"vote": vote, "confidence": 0.90, "analysis": raw_text[:200]}

    async def _call_groq_api(self, model: str, prompt: str, system_prompt: str) -> Dict[str, Any]:
        """Calls Groq OpenAI-compatible REST API asynchronously."""
        if not self.groq_api_key:
            raise ValueError("GROQ_API_KEY missing")

        api_model = model
        if "llama" in api_model:
            api_model = "llama-3.3-70b-versatile"
        elif "qwen" in api_model:
            api_model = "qwen-2.5-72b-instruct"
        elif "mixtral" in api_model:
            api_model = "mixtral-8x7b-32768"

        url = "https://api.groq.com/openai/v1/chat/completions"
        headers = {
            "Authorization": f"Bearer {self.groq_api_key}",
            "Content-Type": "application/json"
        }
        payload = {
            "model": api_model,
            "messages": [
                {"role": "system", "content": system_prompt},
                {"role": "user", "content": prompt}
            ],
            "temperature": 0.1,
            "response_format": {"type": "json_object"}
        }

        loop = asyncio.get_event_loop()
        def _sync_post():
            resp = requests.post(url, headers=headers, json=payload, timeout=8.0)
            resp.raise_for_status()
            return resp.json()

        data = await loop.run_in_executor(None, _sync_post)
        raw_text = data["choices"][0]["message"]["content"].strip()
        return json.loads(raw_text)

    async def _execute_agent(
        self,
        role_key: str,
        spec: Dict[str, Any],
        message: str
    ) -> Dict[str, Any]:
        """Executes a single specialist agent with standby fallback chains."""
        start_time = time.perf_counter()
        role_id = spec.get("role_id", role_key)
        display_name = spec.get("display_name", role_key)
        weight = spec.get("weight", 1.0)
        system_prompt = spec.get("prompt_template", "")

        user_prompt = f"""Phân tích tin nhắn tiếng Việt sau đây dưới góc nhìn chuyên môn của bạn:

\"\"\"{message}\"\"\"

Bắt buộc trả về định dạng JSON thuần túy theo schema sau:
{{
    "role_id": "{role_id}",
    "vote": "SCAM-RISK" | "LOW-RISK" | "UNKNOWN",
    "scam_prob": 0.0 - 1.0,
    "confidence": 0.0 - 1.0,
    "risk_level": "LOW" | "MEDIUM" | "HIGH" | "CRITICAL",
    "key_cues": ["danh sách các từ khóa hoặc dấu hiệu cụ thể"],
    "analysis": "1-2 câu lý giải chuyên môn ngắn gọn"
}}"""

        # Priority chain: primary maker model -> secondary checker model -> standby models
        primary = spec.get("primary_maker_model") or spec.get("primary_model")
        secondary = spec.get("secondary_checker_model")
        raw_chain = [primary, secondary] + spec.get("standby_priority_chain", [])
        chain = [m for m in raw_chain if m]
        last_error = ""
        api_calls_count = 0

        for model_candidate in chain:
            if not model_candidate:
                continue
            if not self.circuit_breaker.is_available(model_candidate):
                logger.info(f"Skipping {model_candidate} for {role_id} (Circuit open).")
                continue

            try:
                # Try calling live API if keys available
                parsed_result = None
                api_calls_count += 1
                if ("gpt" in model_candidate or "sol" in model_candidate or "claude" in model_candidate) and (self.openai_api_key or self.anthropic_api_key):
                    parsed_result = await self._call_vibi_api(model_candidate, user_prompt, system_prompt)
                elif "gemini" in model_candidate and self.gemini_api_key:
                    parsed_result = await self._call_gemini_api(model_candidate, user_prompt, system_prompt)
                elif ("llama" in model_candidate or "qwen" in model_candidate or "mixtral" in model_candidate or "groq" in model_candidate) and self.groq_api_key:
                    parsed_result = await self._call_groq_api(model_candidate, user_prompt, system_prompt)
                elif self.gemini_api_key:
                    parsed_result = await self._call_gemini_api("gemini-3.5-flash-lite", user_prompt, system_prompt)
                elif self.openai_api_key:
                    parsed_result = await self._call_vibi_api("gpt-6.1-sol", user_prompt, system_prompt)
                else:
                    api_calls_count -= 1  # Not a remote API call
                    # Deterministic heuristic fallback when external multi-provider keys are absent
                    parsed_result = self._local_heuristic_agent_eval(role_key, message)

                elapsed_ms = (time.perf_counter() - start_time) * 1000
                self.circuit_breaker.record_success(model_candidate)

                raw_vote = str(parsed_result.get("vote", "LOW-RISK")).upper()
                if any(kw in raw_vote for kw in ["SCAM", "DANGER"]):
                    norm_vote = "SCAM-RISK"
                elif any(kw in raw_vote for kw in ["HAM", "SAFE", "LOW"]):
                    norm_vote = "LOW-RISK"
                else:
                    norm_vote = "UNKNOWN"

                return {
                    "role_key": role_key,
                    "role_id": role_id,
                    "display_name": display_name,
                    "model_used": model_candidate,
                    "weight": weight,
                    "vote": norm_vote,
                    "scam_prob": float(parsed_result.get("scam_prob", 0.5)),
                    "confidence": float(parsed_result.get("confidence", 0.85)),
                    "risk_level": parsed_result.get("risk_level", "LOW"),
                    "key_cues": parsed_result.get("key_cues", []),
                    "analysis": parsed_result.get("analysis", "Phân tích hoàn tất."),
                    "latency_ms": round(elapsed_ms, 2),
                    "api_calls_count": api_calls_count,
                    "status": "SUCCESS",
                }

            except Exception as e:
                last_error = str(e)
                self.circuit_breaker.record_failure(model_candidate)
                logger.warning(f"Agent {role_id} model {model_candidate} failed: {e}. Trying standby.")

        # Graceful fallback if entire chain fails
        elapsed_ms = (time.perf_counter() - start_time) * 1000
        fallback_res = self._local_heuristic_agent_eval(role_key, message)
        return {
            "role_key": role_key,
            "role_id": role_id,
            "display_name": display_name,
            "model_used": "local-rule-fallback",
            "weight": weight,
            "vote": fallback_res.get("vote", "LOW-RISK"),
            "scam_prob": fallback_res.get("scam_prob", 0.5),
            "confidence": fallback_res.get("confidence", 0.70),
            "risk_level": fallback_res.get("risk_level", "LOW"),
            "key_cues": fallback_res.get("key_cues", []),
            "analysis": f"Fallback nội bộ do toàn bộ chuỗi mô hình gián đoạn ({last_error}).",
            "latency_ms": round(elapsed_ms, 2),
            "api_calls_count": api_calls_count,
            "status": "DEGRADED_FALLBACK",
        }

    def _local_heuristic_agent_eval(self, role_key: str, message: str) -> Dict[str, Any]:
        """Provides expert domain heuristics when cloud APIs are unconfigured or throttled."""
        msg_lower = message.lower()
        has_url = "http" in msg_lower or ".com" in msg_lower or ".vn" in msg_lower or ".me" in msg_lower
        has_urgency = any(w in msg_lower for w in ["khoa", "khan cap", "trong 24h", "lap tuc", "ngay bay gio"])
        has_bank = any(w in msg_lower for w in ["vcb", "vietcombank", "mbbank", "techcombank", "otp", "sinh trac hoc", "so du"])
        has_greed = any(w in msg_lower for w in ["trung thuong", "ctv", "kiem tien", "hoa hong", "qua tang"])
        has_teencode = any(w in msg_lower for w in ["t4i kh04n", "n9an h4n9", "l1nk", "x4c thuc", "vui l0ng"])

        if role_key == "cyber_threat_url_inspector":
            if has_url and not any(valid in msg_lower for valid in ["vietcombank.com.vn", "mbbank.com.vn", "techcombank.com.vn"]):
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.95, "confidence": 0.92, "risk_level": "CRITICAL",
                    "key_cues": ["Tên miền lạ / không chính ngạch", "URL giả mạo"],
                    "analysis": "Phát hiện liên kết ngoài hạ tầng ngân hàng chính thức, nguy cơ phishing cao."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.10, "confidence": 0.90, "risk_level": "LOW",
                "key_cues": ["Không có link độc hại"], "analysis": "Hạ tầng URL an toàn hoặc không chứa liên kết."
            }

        elif role_key == "cyber_financial_analyst":
            # Merged URL & Banking Protocol Inspection
            is_scam_url = has_url and not any(valid in msg_lower for valid in ["vietcombank.com.vn", "mbbank.com.vn", "techcombank.com.vn"])
            is_bank_violation = has_bank and ("nhap ma" in msg_lower or "truy cap" in msg_lower or "cap nhat sinh trac" in msg_lower or "khoa" in msg_lower)
            if is_scam_url or is_bank_violation:
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.97, "confidence": 0.96, "risk_level": "CRITICAL",
                    "key_cues": ["Vi phạm QĐ 2345/QĐ-NHNN", "Liên kết ngân hàng giả mạo"],
                    "analysis": "Phát hiện liên kết mạo danh hạ tầng ngân hàng hoặc yêu cầu can thiệp tài khoản trái quy chuẩn NHNN."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.08, "confidence": 0.92, "risk_level": "LOW",
                "key_cues": ["Giao thức tài chính an toàn"], "analysis": "Nội dung tuân thủ quy chuẩn thông báo giao dịch thông thường."
            }

        elif role_key == "social_engineering_profiler":
            if has_urgency or has_greed:
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.88, "confidence": 0.89, "risk_level": "HIGH",
                    "key_cues": ["Tạo áp lực thời gian khẩn cấp", "Mồi chài tài chính"],
                    "analysis": "Có dấu hiệu thao túng tâm lý sợ hãi bị khóa tài khoản hoặc bẫy việc làm ảo."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.15, "confidence": 0.85, "risk_level": "LOW",
                "key_cues": ["Văn phong trung tính"], "analysis": "Không ghi nhận áp lực tâm lý hay mồi chài bất thường."
            }

        elif role_key == "psycholinguistic_slang_profiler":
            # Merged Social Engineering & Teencode Evasion Profiler
            if has_urgency or has_greed or has_teencode:
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.92, "confidence": 0.93, "risk_level": "HIGH",
                    "key_cues": ["Thao túng tâm lý", "Biến thể teencode lách lọc"],
                    "analysis": "Phát hiện kỹ thuật tạo áp lực tâm lý khẩn cấp kết hợp ngụy trang teencode để vượt qua bộ lọc viễn thông."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.12, "confidence": 0.88, "risk_level": "LOW",
                "key_cues": ["Ngôn ngữ tự nhiên", "Không áp lực"], "analysis": "Ngữ pháp tiếng Việt tự nhiên, không ghi nhận đòn bẩy tâm lý hay từ khóa ngụy trang."
            }

        elif role_key == "vietnamese_teencode_analyst":
            if has_teencode:
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.90, "confidence": 0.91, "risk_level": "HIGH",
                    "key_cues": ["Cố ý thay thế ký tự số", "Ngôn ngữ teencode lách bộ lọc"],
                    "analysis": "Phát hiện từ khóa bị cố tình ngụy trang nhằm vượt mặt hệ sinh thái lọc từ khóa viễn thông."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.20, "confidence": 0.88, "risk_level": "LOW",
                "key_cues": ["Ngôn ngữ chuẩn mực"], "analysis": "Ngữ pháp tiếng Việt tự nhiên, không có biến thể lách lọc."
            }

        elif role_key == "banking_protocol_verifier":
            if has_bank and ("nhap ma" in msg_lower or "truy cap" in msg_lower or "cap nhat sinh trac" in msg_lower):
                return {
                    "vote": "SCAM-RISK", "scam_prob": 0.96, "confidence": 0.95, "risk_level": "CRITICAL",
                    "key_cues": ["Vi phạm quy định NHNN", "Yêu cầu click link cập nhật thông tin"],
                    "analysis": "Theo Quyết định 2345/QĐ-NHNN, ngân hàng không bao giờ yêu cầu click link tin nhắn để cập nhật thông tin hay sinh trắc học."
                }
            return {
                "vote": "LOW-RISK", "scam_prob": 0.12, "confidence": 0.90, "risk_level": "LOW",
                "key_cues": ["Đúng định dạng thông báo"], "analysis": "Nội dung phù hợp quy trình thông báo biến động số dư hoặc OTP tiêu chuẩn."
            }

        elif role_key == "public_defender_advocate":
            # Advocate for LOW-RISK if standard bank transaction OTP or utility notice
            if "ma otp" in msg_lower or "khong chia se ma nay" in msg_lower or "tien dien" in msg_lower:
                return {
                    "vote": "LOW-RISK", "scam_prob": 0.05, "confidence": 0.96, "risk_level": "LOW",
                    "key_cues": ["Khuyến cáo bảo mật chuẩn", "Cấu trúc tin nhắn hệ thống"],
                    "analysis": "Tin nhắn chứa cảnh báo 'Không chia sẻ mã này' và mã số OTP tiêu chuẩn. Đây là thông báo dịch vụ an toàn, đề xuất bảo vệ nhãn LOW-RISK để tránh Alarm Fatigue."
                }
            return {
                "vote": "LOW-RISK" if not (has_url and has_urgency) else "SCAM-RISK",
                "scam_prob": 0.35 if not (has_url and has_urgency) else 0.80,
                "confidence": 0.80,
                "risk_level": "LOW" if not (has_url and has_urgency) else "HIGH",
                "key_cues": ["Đánh giá tổng quan tính khách quan"],
                "analysis": "Không đủ bằng chứng đanh thép để khẳng định lừa đảo; ưu tiên bảo toàn giao dịch người dùng."
            }

        return {"vote": "LOW-RISK", "scam_prob": 0.20, "confidence": 0.80, "risk_level": "LOW", "key_cues": [], "analysis": "Trung tính."}

    async def evaluate_council(self, message: str, active_roles: Optional[List[str]] = None) -> Dict[str, Any]:
        """
        Coordinates forensic specialists concurrently with Early-Exit Fast-Path.
        Supports dynamic role ablation (e.g. 3-Agent vs 5-Agent).
        """
        start_overall = time.perf_counter()
        tasks = []
        roles_to_run = active_roles or self.active_roles or list(self.specialists.keys())

        for key in roles_to_run:
            if key in self.specialists:
                spec = self.specialists[key]
                tasks.append(asyncio.create_task(self._execute_agent(key, spec, message)))

        early_exit_enabled = self.config.get("council_metadata", {}).get("early_exit_enabled", True)
        early_exit_threshold = 4 if len(roles_to_run) >= 5 else (len(roles_to_run) if len(roles_to_run) <= 3 else 3)
        completed_results: List[Dict[str, Any]] = []
        early_exit_triggered = False

        # Gather results with potential early exit
        for coro in asyncio.as_completed(tasks):
            res = await coro
            completed_results.append(res)
            
            # Check for Early-Exit Fast Path
            if early_exit_enabled and len(completed_results) >= early_exit_threshold:
                scam_votes = sum(1 for r in completed_results if r["vote"] == "SCAM-RISK")
                ham_votes = sum(1 for r in completed_results if r["vote"] == "LOW-RISK")
                if scam_votes >= early_exit_threshold or ham_votes >= early_exit_threshold:
                    early_exit_triggered = True
                    logger.info(
                        f"Early-Exit Supermajority reached ({scam_votes} SCAM-RISK vs {ham_votes} LOW-RISK out of {len(completed_results)}). "
                        f"Resolving early to optimize latency."
                    )
                    break

        # Await remaining tasks in background if early exit to avoid unhandled exceptions
        if early_exit_triggered:
            for t in tasks:
                if not t.done():
                    t.cancel()

        # Weighted Consensus Calculation (Borda Count & Public Defender Rules)
        total_weight = sum(r["weight"] for r in completed_results)
        weighted_scam_prob = sum(r["weight"] * r["scam_prob"] for r in completed_results) / (total_weight or 1.0)
        
        # Check Public Defender Advocate input
        pd_result = next((r for r in completed_results if r["role_key"] == "public_defender_advocate"), None)
        defender_intervened = False
        if pd_result and pd_result["vote"] == "LOW-RISK" and pd_result["confidence"] >= 0.80:
            # Public Defender strongly defends legitimacy -> Apply anti-false-alarm boost
            veto_boost = self.consensus_rules.get("public_defender_veto_boost", 0.25)
            weighted_scam_prob = max(0.0, weighted_scam_prob - veto_boost)
            defender_intervened = True
            logger.info("Public Defender intervened: Reduced scam probability to avoid False Positive Alarm Fatigue.")

        # Determine Final Label (SCAM-RISK, LOW-RISK, UNKNOWN)
        scam_votes = sum(1 for r in completed_results if r["vote"] == "SCAM-RISK")
        ham_votes = sum(1 for r in completed_results if r["vote"] == "LOW-RISK")
        unanimous_thresh = self.consensus_rules.get("unanimous_scam_threshold", 0.85)
        scam_risk_thresh = self.consensus_rules.get("scam_risk_threshold", self.consensus_rules.get("suspected_scam_threshold", 0.60))
        low_risk_thresh = self.consensus_rules.get("low_risk_threshold", self.consensus_rules.get("ham_threshold", 0.40))
        
        # Check for vote contradiction / tie / ambiguity
        vote_contradiction = (scam_votes > 0 and ham_votes > 0 and abs(scam_votes - ham_votes) <= 1)

        if weighted_scam_prob >= scam_risk_thresh and not (vote_contradiction and weighted_scam_prob < 0.68):
            final_label = "SCAM-RISK"
            risk_level = "CRITICAL" if weighted_scam_prob >= unanimous_thresh else "HIGH"
        elif weighted_scam_prob < low_risk_thresh and not vote_contradiction:
            final_label = "LOW-RISK"
            risk_level = "LOW"
        else:
            final_label = "UNKNOWN"
            risk_level = "MEDIUM"

        total_elapsed_ms = (time.perf_counter() - start_overall) * 1000

        # Synthesize Multi-Perspective Rationale
        analyses = [f"- **{r['display_name']} ({r['model_used']})**: {r['analysis']}" for r in completed_results]
        conclusion_map = {
            "SCAM-RISK": "🚨 NGUY CƠ LỪA ĐẢO (SCAM-RISK)",
            "LOW-RISK": "✓ AN TOÀN / GIAO DỊCH HỢP PHÁP (LOW-RISK)",
            "UNKNOWN": "⚠️ KHÔNG XÁC ĐỊNH / VÙNG PHÂN VÂN (UNKNOWN - CẦN THẨM ĐỊNH THÊM)",
        }
        unified_rationale = (
            f"**Kết luận Hội đồng:** {conclusion_map.get(final_label, final_label)}.\n"
            f"Tỷ lệ đồng thuận điều chỉnh: {weighted_scam_prob*100:.1f}%. "
            f"({'Kích hoạt Early-Exit Fast-Path' if early_exit_triggered else f'Biểu quyết đầy đủ {len(completed_results)} thành viên'}).\n"
            + "\n".join(analyses)
        )

        total_api_calls = sum(r.get("api_calls_count", 0) for r in completed_results)

        return {
            "message": message,
            "final_label": final_label,
            "consensus_scam_prob": round(weighted_scam_prob, 4),
            "risk_level": risk_level,
            "total_latency_ms": round(total_elapsed_ms, 2),
            "early_exit_triggered": early_exit_triggered,
            "defender_intervened": defender_intervened,
            "total_api_calls": total_api_calls,
            "specialist_votes": {r["role_key"]: r for r in completed_results},
            "unified_rationale": unified_rationale,
            "active_council_size": len(completed_results),
            "estimated_council_cost_usd": round(0.00015 * len(completed_results), 6),
        }

    def evaluate_sync(self, message: str, active_roles: Optional[List[str]] = None) -> Dict[str, Any]:
        """Synchronous wrapper for integration with standard pipelines."""
        return asyncio.run(self.evaluate_council(message, active_roles=active_roles))


if __name__ == "__main__":
    import sys
    if sys.stdout.encoding.lower() != "utf-8":
        try:
            sys.stdout.reconfigure(encoding="utf-8")
        except Exception:
            pass
    council = ForensicCouncil()
    test_msg = "Vietcombank tran trong thong bao: Tai khoan cua quy khach da bi khoa, vui long truy cap https://vcb-digibank-login.com de xac thuc ngay."
    print("Testing Forensic Council on scam SMS...")
    res = council.evaluate_sync(test_msg)
    print("Final Label:", res["final_label"])
    print("Consensus Score:", res["consensus_scam_prob"])
    print("Latency:", res["total_latency_ms"], "ms")
    print("Rationale:\n", res["unified_rationale"].encode("utf-8", errors="ignore").decode("utf-8"))

