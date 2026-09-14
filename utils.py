#!/usr/bin/env python3
import os
import re
import json
import threading
import httpx
import openai
import tiktoken
from datetime import datetime
from dotenv import load_dotenv
from typing import List, Dict, Any, Tuple
from concurrent.futures import ThreadPoolExecutor, as_completed

# Load environment variables from .env file
load_dotenv()

_REPO_ROOT = os.path.dirname(os.path.abspath(__file__))
_provider_state = threading.local()
_provider_log_lock = threading.Lock()


def set_llm_call_context(call_id, role):
    """Label requests made on this thread until end_llm_call_context()."""
    _provider_state.context = {"call_id": call_id, "role": role}
    _provider_state.record = None


def end_llm_call_context():
    """Clear the label and return the provider record of the last request on this thread."""
    _provider_state.context = None
    return getattr(_provider_state, "record", None)


def provider_log_path():
    """ACE_PROVIDER_LOG, else results/provider_log/provider_<date>.jsonl under the repo."""
    return (os.getenv("ACE_PROVIDER_LOG", "").strip()
            or os.path.join(_REPO_ROOT, "results", "provider_log",
                            f"provider_{datetime.now():%Y%m%d}.jsonl"))


def _log_provider_record(request, status, payload, body):
    """Append one line per chat-completions HTTP response, SDK retries included.

    The gateway routes one model slug across several hosts per call
    (provider_metadata.gateway.routing), and the host can differ between
    experiment arms; this log is the only record of which host served what.
    A write failure is deliberately not caught: a run that cannot record its
    hosts should stop rather than continue unaudited.
    """
    try:
        sent = json.loads(request.content or b"{}")
    except (ValueError, httpx.RequestNotRead):
        sent = {}
    data = payload.get("data") if isinstance(payload, dict) else None
    data = data if isinstance(data, dict) else {}
    choice = (data.get("choices") or [{}])[0]
    metadata = (choice.get("message") or {}).get("provider_metadata")
    routing = ((metadata or {}).get("gateway") or {}).get("routing") or {}
    context = getattr(_provider_state, "context", None) or {}
    record = {
        "logged_at": datetime.now().isoformat(),
        "call_id": context.get("call_id"),
        "role": context.get("role"),
        "http_status": status,
        "request_model": sent.get("model"),
        "generation_id": data.get("id"),
        "echoed_model": data.get("model"),
        "finish_reason": choice.get("finish_reason"),
        "resolvedProvider": routing.get("resolvedProvider"),
        "finalProvider": routing.get("finalProvider"),
        "modelAttemptCount": routing.get("modelAttemptCount"),
        "totalProviderAttemptCount": routing.get("totalProviderAttemptCount"),
        "usage": data.get("usage"),
        "provider_metadata": metadata,
        "error_body": None if data.get("choices") else body[:4000].decode("utf-8", "replace"),
    }
    path = provider_log_path()
    os.makedirs(os.path.dirname(path), exist_ok=True)
    with _provider_log_lock, open(path, "a", encoding="utf-8") as f:
        f.write(json.dumps(record, ensure_ascii=False) + "\n")
    _provider_state.record = record


class _ClineUnwrapTransport(httpx.HTTPTransport):
    """Undo the Cline API's response envelope so the OpenAI SDK can parse it.

    Cline answers chat completions as {"success": true, "data": {...}} rather
    than the bare OpenAI object. The SDK parses that to choices=None, which
    timed_llm_call raises as "Empty response from API" - and that is classified
    retryable, so an unpatched run does not fail, it sleeps and retries for
    hours. Measured 2026-09-03.

    Deliberately left alone: GET /models, whose {"data": [...]} already matches
    what the SDK expects (data is a list there, not a dict with choices), and
    any non-JSON or streamed body.

    Every chat-completions response, JSON or not, is also written to the
    provider log (see _log_provider_record) before it is unwrapped.
    """

    def handle_request(self, request):
        response = super().handle_request(request)
        content_type = response.headers.get("content-type", "")
        is_chat = request.method == "POST" and request.url.path.endswith("/chat/completions")
        is_json = "application/json" in content_type
        if "text/event-stream" in content_type or not (is_json or is_chat):
            return response

        response.read()
        body = response.content
        status = response.status_code
        try:
            payload = json.loads(body) if is_json else None
        except ValueError:
            payload = None

        if is_chat:
            _log_provider_record(request, status, payload, body)

        if isinstance(payload, dict):
            data = payload.get("data")
            if isinstance(data, dict) and "choices" in data:
                body = json.dumps(data).encode("utf-8")
            elif payload.get("success") is False and status == 200:
                # A failure delivered with a 2xx status would otherwise look
                # like an empty response and be retried forever. Make it loud.
                status = 502

        headers = httpx.Headers(response.headers)
        headers.pop("content-encoding", None)  # body is already decoded
        headers["content-length"] = str(len(body))
        return httpx.Response(status_code=status, headers=headers,
                              content=body, request=request)


def initialize_clients(api_provider):
    """Initialize separate clients for generator, reflector, and curator"""
    if api_provider == "sambanova":
        # Use SambaNova API
        base_url = "https://api.sambanova.ai/v1"
        api_key = os.getenv('SAMBANOVA_API_KEY', '')
        if not api_key:
            raise ValueError("SambaNova api key not found in environment variables")
    elif api_provider == "together":
        # Use Together API
        base_url = "https://api.together.xyz/v1"
        api_key = os.getenv('TOGETHER_API_KEY', '')
        if not api_key:
            raise ValueError("Together api key not found in environment variables")
    elif api_provider == "openai":
        # Use OpenAI API
        base_url = "https://api.openai.com/v1"
        api_key = os.getenv('OPENAI_API_KEY', '')
        if not api_key:
            raise ValueError("OpenAI api key not found in environment variables")
    elif api_provider == "groq":
        # Use Groq's OpenAI-compatible API
        base_url = os.getenv('GROQ_BASE_URL', '').strip() or "https://api.groq.com/openai/v1"
        api_key = os.getenv('GROQ_API_KEY', '')
        if not api_key:
            raise ValueError("Groq api key not found in environment variables")
    elif api_provider == "gemini":
        # Use Google Gemini's OpenAI-compatible API
        gemini_default = "https://generativelanguage.googleapis.com/v1beta/openai/"
        base_url = os.getenv('GEMINI_BASE_URL', '').strip() or gemini_default
        api_key = os.getenv('GEMINI_API_KEY', '')
        if not api_key:
            raise ValueError("Gemini api key not found in environment variables")
    elif api_provider == "clinepass":
        # Use the Cline API (ClinePass subscription), which is OpenAI-compatible.
        base_url = os.getenv('CLINE_BASE_URL', '').strip() or "https://api.cline.bot/api/v1"
        api_key = os.getenv('CLINE_API_KEY', '')
        if not api_key:
            raise ValueError("Cline api key not found in environment variables")
    elif api_provider == "ollama":
        # Use a local Ollama server's OpenAI-compatible API. Ollama ignores the
        # key, but the OpenAI SDK requires a non-empty one.
        base_url = os.getenv('OLLAMA_BASE_URL', '').strip() or "http://localhost:11434/v1"
        api_key = os.getenv('OLLAMA_API_KEY', '').strip() or "ollama"
    elif api_provider == "commonstack":
        # Use Commonstack API
        base_url = "https://api.commonstack.ai/v1"
        api_key = os.getenv('COMMONSTACK_API_KEY', '')
        if not api_key:
            raise ValueError("Commonstack api key not found in environment variables")
    else:
        raise ValueError(
            f"Invalid api_provider name: {api_provider}. Must be 'sambanova', "
            f"'together', 'openai', 'groq', 'gemini', 'clinepass', 'ollama', "
            f"or 'commonstack'"
        )
        
    def _make_client():
        kwargs = {"api_key": api_key, "base_url": base_url}
        if api_provider == "clinepass":
            # Our own httpx.Client defaults to a 5s timeout, which is far too
            # short for an LLM call, so set it explicitly alongside the shim.
            kwargs["http_client"] = httpx.Client(
                transport=_ClineUnwrapTransport(),
                timeout=httpx.Timeout(600.0, connect=10.0),
            )
        return openai.OpenAI(**kwargs)

    generator_client = _make_client()
    reflector_client = _make_client()
    curator_client = _make_client()
    
    print(f"Using {api_provider} API for all models ({base_url})")
    return generator_client, reflector_client, curator_client

def get_section_slug(section_name):
    """Convert section name to slug format (3-5 chars)"""
    # Common section mappings - updated to match original sections
    slug_map = {
        "financial_strategies_and_insights": "fin",
        "formulas_and_calculations": "calc",
        "code_snippets_and_templates": "code",
        "common_mistakes_to_avoid": "err",
        "problem_solving_heuristics": "prob",
        "context_clues_and_indicators": "ctx",
        "others": "misc",
        "meta_strategies": "meta"
    }
    
    # Clean and convert to snake_case
    clean_name = section_name.lower().strip().replace(" ", "_").replace("&", "and")
    
    if clean_name in slug_map:
        return slug_map[clean_name]
    
    # Generate slug from first letters
    words = clean_name.split("_")
    if len(words) == 1:
        return words[0][:4]
    else:
        return "".join(w[0] for w in words[:5])

def extract_boxed_content(text):
    """Helper function to extract content from \\boxed{} format"""
    pattern = r'\\boxed\{'
    match = re.search(pattern, text)
    if not match:
        return None
    
    start = match.end() - 1  # Position of opening brace
    brace_count = 0
    i = start
    
    while i < len(text):
        if text[i] == '{':
            brace_count += 1
        elif text[i] == '}':
            brace_count -= 1
            if brace_count == 0:
                return text[start + 1:i]  # Content between braces
        i += 1
    return None

def extract_answer(response):
    """Extract final answer from model response"""
    try:
        # First try JSON parsing
        parsed = json.loads(response)
        answer = str(parsed.get("final_answer", "No final answer found"))
        return answer  
            
    except (json.JSONDecodeError, KeyError, AttributeError):
        # JSON parsing failed, use fallback logic
        matches = re.findall(r"Finish\[(.*?)\]", response)
        if matches:
            answer = matches[-1]
            return answer
        
        # Try to get final answer from JSON style response with regex matching 
        # Try double quotes first
        matches = re.findall(r'"final_answer"\s*:\s*"([^"]*)"', response)
        if matches:
            answer = matches[-1]
            return answer
        
        # Try single quotes
        matches = re.findall(r"'final_answer'\s*:\s*'([^']*)'", response)
        if matches:
            answer = matches[-1]
            return answer
        
        # Handle JSON format without quotes (for simple expressions)
        matches = re.findall(r'[\'"]final_answer[\'"]\s*:\s*([^,}]+)', response)
        if matches:
            answer = matches[-1].strip()
            # Clean up trailing characters
            answer = re.sub(r'[,}]*$', '', answer)
            return answer
        
        # Fallback for "The final answer is: X" pattern with boxed
        final_answer_pattern = r'[Tt]he final answer is:?\s*\$?\\boxed\{'
        match = re.search(final_answer_pattern, response)
        if match:
            # Extract boxed content starting from this match
            remaining_text = response[match.start():]
            boxed_content = extract_boxed_content(remaining_text)
            if boxed_content:
                return boxed_content
        
        # More general pattern for "final answer is X"
        matches = re.findall(r'[Tt]he final answer is:?\s*([^\n.]+)', response)
        if matches:
            answer = matches[-1].strip()
            # Clean up common formatting
            answer = re.sub(r'^\$?\\boxed\{([^}]+)\}\$?$', r'\1', answer)
            answer = answer.replace('$', '').strip()
            if answer:
                return answer
        
        return "No final answer found"
    
enc = tiktoken.get_encoding("cl100k_base")
def count_tokens(prompt: str) -> int:
    return len(enc.encode(prompt))


def evaluate_single_test_sample(args_tuple, data_processor) -> Tuple[Dict, str]:
    """
    Evaluate a single test sample - task-agnostic implementation.
    
    Args:
        args_tuple: Tuple of (index, task_dict, generator, playbook, max_tokens, log_dir, use_json_mode)
        data_processor: DataProcessor instance with answer_is_correct method
    """
    (i, task_dict, generator, playbook, max_tokens, log_dir, use_json_mode) = args_tuple
    try:
        context = task_dict["context"]
        question = task_dict["question"]
        target = task_dict["target"]

        gen_response, bullet_ids, call_info = generator.generate(
            question=question,
            playbook=playbook,
            context=context,
            reflection="(empty)",
            use_json_mode=use_json_mode,
            call_id=f"test_eval_{i}",
            log_dir=log_dir
        )

        final_answer = extract_answer(gen_response)
        is_correct = data_processor.answer_is_correct(final_answer, target)

        return {
            "index": i,
            "final_answer": final_answer,
            "target": target,
            "is_correct": is_correct,
            "success": True
        }, None

    except Exception as e:
        return None, f"Error evaluating sample {i}: {type(e).__name__}: {str(e)}"


def evaluate_test_set(data_processor, generator, playbook, test_samples,
                      max_tokens=4096, log_dir=None, max_workers=20, 
                      use_json_mode=False) -> Tuple[Dict, Dict]:
    """
    Parallel evaluation of test set - task-agnostic implementation.
    
    Args:
        data_processor: DataProcessor instance with answer_is_correct and evaluate_accuracy methods
        generator: Generator instance
        playbook: Current playbook string
        test_samples: List of test samples
        max_tokens: Max tokens for generation
        log_dir: Directory for logs
        max_workers: Number of parallel workers
        use_json_mode: Whether to use JSON mode
        
    Returns:
        Tuple of (results_dict, error_logs_dict)
    """
    print(f"\n{'='*40}")
    print(f"EVALUATING TEST SET - {len(test_samples)} samples, {max_workers} workers")
    print(f"{'='*40}")

    args_list = [
        (i, sample, generator, playbook, max_tokens, log_dir, use_json_mode)
        for i, sample in enumerate(test_samples)
    ]

    results = {
        "correct": 0, "total": 0, "no_answer": 0,
        "answers": [], "targets": [], "errors": []
    }

    # Use a wrapper to pass data_processor to the evaluation function
    def eval_wrapper(args_tuple):
        return evaluate_single_test_sample(args_tuple, data_processor)

    with ThreadPoolExecutor(max_workers=max_workers) as executor:
        future_to_args = {
            executor.submit(eval_wrapper, args): args 
            for args in args_list
        }

        for i, future in enumerate(as_completed(future_to_args), 1):
            result, error = future.result()
            
            if error:
                print(error)
                continue

            if result and result["success"]:
                results["correct"] += (1 if result["is_correct"] else 0)
                results["total"] += 1
                results["answers"].append(result["final_answer"])
                results["targets"].append(result["target"])
                
                if not result["is_correct"]:
                    results["errors"].append({
                        "index": result["index"],
                        "prediction": result["final_answer"],
                        "ground_truth": result["target"]
                    })
                
                if result["final_answer"] == "No final answer found":
                    results["no_answer"] += 1

            if i % 50 == 0:
                curr_acc = results["correct"] / results["total"] if results["total"] > 0 else 0
                print(f"Progress: {i}/{len(args_list)}, Accuracy: {curr_acc:.3f}")
    
    if results["answers"] and results["targets"]:
        accuracy = data_processor.evaluate_accuracy(results["answers"], results["targets"])
        
        final_results = {
            "accuracy": accuracy,
            "correct": results["correct"],
            "total": results["total"],
            "no_answer": results["no_answer"]
        }
        
        error_logs = {
            "accuracy": accuracy,
            "errors": results["errors"]
        }
        
        print(f"\n📊 Final Accuracy: {accuracy:.3f} ({results['correct']}/{results['total']})")
    else:
        results = {"accuracy": 0.0, "correct": 0, "total": 0}
        error_logs = {}
        print(f"\n📊 No valid results!")
        
    return final_results, error_logs
