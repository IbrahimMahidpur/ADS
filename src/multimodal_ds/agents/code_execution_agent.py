"""
Code Execution Agent — hardened sandbox with resource limits.
FIX: working_dir now includes session_id for session isolation.
"""
import logging
import os
import subprocess
import sys
import tempfile
import time
from pathlib import Path
from typing import Optional

import httpx

from multimodal_ds.config import CODE_GEN_MODEL, CODE_FIX_MODEL, LLM_TIMEOUT, OUTPUT_DIR
from multimodal_ds.memory.agent_memory import AgentMemory
from multimodal_ds.core.llm_client import chat_with_fallback
from multimodal_ds.core.observability import agent_span, get_session_tracker

logger = logging.getLogger(__name__)

_CPU_SECONDS    = int(os.getenv("SANDBOX_CPU_SECONDS",  "60"))
_MEM_MB         = int(os.getenv("SANDBOX_MEM_MB",       "512"))
_STDOUT_CHARS   = int(os.getenv("SANDBOX_STDOUT_CHARS", "8000"))
_PROC_TIMEOUT_S = int(os.getenv("SANDBOX_TIMEOUT_S",    "300"))

SYSTEM_PROMPT = """You are a senior data scientist with 50+ years of production ML experience.

CRITICAL DATA PREPROCESSING (MUST DO BEFORE ANY MODELING):
1. Drop ID columns like 'CustomerID', 'id', 'ID' - never use them as features
2. Identify categorical columns: columns with dtype 'object' that are NOT the target
3. Encode categorical features using: from sklearn.preprocessing import LabelEncoder OR pd.get_dummies()
4. Encode target variable if it's string (e.g., 'Yes'/'No' -> 1/0): df['target'] = df['target'].map({'Yes': 1, 'No': 0})
5. Convert all features to numeric: use LabelEncoder for single columns, get_dummies for multiple

BEFORE writing any code, you MUST:
1. Print df.columns.tolist() and df.shape — NEVER assume column names
2. Print df.dtypes and df.head(3)
3. Print df.describe() for all numeric columns
4. Print df.isnull().sum() for missing value audit

STATISTICAL DISCIPLINE (enforce these without exception):
- If normality is violated: use Mann-Whitney U instead of t-test, Spearman instead of Pearson
- If multicollinearity is present (VIF > 10): remove correlated features before modeling
- If n < 30: do not run parametric tests, note sample size limitation in output
- If target is imbalanced (minority class < 20%): use class_weight='balanced' and report F1/AUC not accuracy
- Always check for data leakage: never use future-dated features or target-derived features in training

CODE STANDARDS (non-negotiable):
- matplotlib.use('Agg') as the very first matplotlib line
- Never call plt.show() — always plt.savefig('filename.png', dpi=150, bbox_inches='tight')
- Save ALL models: joblib.dump(model, 'model_{name}.pkl')
- Save feature importances: pd.DataFrame({'feature': names, 'importance': values}).to_csv('feature_importance.csv', index=False)
- End every script with: print('=== FINDINGS ===') then 3-5 quantitative sentences with actual numbers

ERROR HANDLING:
- Wrap all file operations in try/except
- Print the actual error message, do not silently pass
- If a column is missing, print available columns and stop gracefully
- For string formatting with potential strings, convert to numeric first

Output ONLY valid Python code inside ```python ... ``` fences. No commentary outside."""


def _sandbox_preexec() -> None:
    try:
        import resource
        # Limit CPU time
        resource.setrlimit(resource.RLIMIT_CPU, (_CPU_SECONDS, _CPU_SECONDS))
        # Limit memory (address space)
        mem_bytes = _MEM_MB * 1024 * 1024
        resource.setrlimit(resource.RLIMIT_AS, (mem_bytes, mem_bytes))
        # Limit number of processes to prevent fork‑bomb attacks
        resource.setrlimit(resource.RLIMIT_NPROC, (64, 64))
    except Exception:
        pass


class CodeExecutionAgent:
    AGENT_NAME = "code_execution_agent"

    def __init__(self, working_dir: Optional[str] = None, session_id: str = "default"):
        # FIX: include session_id in working_dir for session isolation
        base = Path(working_dir) if working_dir else Path(OUTPUT_DIR)
        self.working_dir = base / session_id
        self.working_dir.mkdir(parents=True, exist_ok=True)
        self.session_id = session_id
        self.memory = AgentMemory()
        self._tracker = get_session_tracker(session_id)

    def execute_task(self, task: dict, data_context: str = "", file_paths: Optional[list] = None, max_retries: int = 2) -> dict:
        task_desc = task.get("description", str(task))
        task_name = task.get("name", "task")
        logger.info(f"[CodeAgent] Executing: {task_name}")

        with agent_span(self.AGENT_NAME, self.session_id, self._tracker) as span:
            span.set_metadata({"task_name": task_name})
            past_context = self._get_relevant_memory(task_desc)
            code = self._generate_code(task_desc, data_context, past_context)
            if not code:
                return {"success": False, "error": "Code generation failed", "code": "", "output": "", "files_created": []}
            span.set_chars(input_chars=len(task_desc) + len(data_context), output_chars=len(code))
            result = self._execute_with_retry(code, task_desc, data_context, file_paths, max_retries)
            span.set_metadata({"task_name": task_name, "success": result["success"], "files_created": result["files_created"]})

        status_msg = "successfully" if result["success"] else "with errors"
        self.memory.store_analysis_step(
            step_name=task_name,
            result=f"Code executed {status_msg}.\nOutput: {result['output'][:500]}\nFiles: {result['files_created']}",
            session_id=self.session_id,
        )
        return result

    def execute(self, task_description: str, data_context: str = "", file_paths: Optional[list] = None, max_retries: int = 2) -> dict:
        from pathlib import Path as _Path
        rag_context = self._retrieve_rag_context(task_description)
        if rag_context:
            data_context = f"Relevant document context (from ChromaDB):\n{rag_context}\n\n" + data_context
            
        exclude_keywords = []
        task_lower = task_description.lower()
        if any(w in task_lower for w in ["visual", "plot", "chart", "graph"]):
            exclude_keywords.extend(["stat_", "normality", "correlation", "tuning", "optuna"])
        elif any(w in task_lower for w in ["model", "train", "predict"]):
            exclude_keywords.extend(["chart", "plot", "html"])
            
        from multimodal_ds.core.context_pool import get_context_pool
        pool = get_context_pool(self.session_id)
        
        pool_summary = pool.get_summary(max_chars=800, exclude_keywords=exclude_keywords)
        if pool_summary and pool_summary != "No shared context yet.":
            data_context = f"Shared session context from other agents:\n{pool_summary}\n\n" + data_context
            
        task = {"name": task_description[:80], "description": task_description}
        return self.execute_task(task=task, data_context=data_context, file_paths=file_paths, max_retries=max_retries)

    def _retrieve_rag_context(self, query: str, k: int = 4) -> str:
        try:
            results = self.memory.retrieve(query, n_results=k)
            if results:
                return "\n\n".join(r["content"] for r in results if r.get("content"))
        except Exception:
            pass
        return ""

    def _inject_statistical_constraints(self, constraints: list) -> list:
        """Append Optuna tuning constraints to the list if available.

        Retrieves tuning results from the shared context pool for this session. If a
        best overall model is present, formats the model name and its best hyper‑
        parameters as a Python comment string and adds it to ``constraints``.
        Returns the updated list.
        """
        from multimodal_ds.core.context_pool import get_context_pool
        import json
        try:
            pool = get_context_pool(self.session_id)
            tuning = pool.get("tuning_results", {})
            if tuning and tuning.get("best_overall_model"):
                best_model = tuning["best_overall_model"]
                best_params = tuning.get("best_params", {})
                param_str = json.dumps(best_params, indent=2)
                constraint = f"# Optuna tuning result: best model = {best_model} with params = {param_str}"
                constraints.append(constraint)
        except Exception as e:
            logger.debug(f"[CodeAgent] Failed to inject tuning constraints: {e}")
        return constraints
    def _generate_code(self, task_desc: str, data_context: str, past_context: str) -> str:
        """Generate Python code for a task.

        The method builds a prompt that includes:
        * the task description and provided data context,
        * any past relevant memory,
        * statistical constraints (e.g., Optuna tuning results),
        * cross‑session lessons via the ReflectionAgent.
        The LLM is then called and the extracted code is returned.
        """
        # Build constraints list and inject Optuna tuning info if available
        constraints: list = []
        constraints = self._inject_statistical_constraints(constraints)
        constraint_section = "\n".join(constraints) + ("\n\n" if constraints else "")
        prompt = f"""Task: {task_desc}\nData Context:\n{data_context[:1500]}\nPrevious Context:\n{past_context[:500]}\n{constraint_section}Working directory: {self.working_dir}\nWrite Python code. Save all outputs to the current directory."""
        # Retrieve relevant past lessons from AgentMemory
        try:
            from multimodal_ds.memory.agent_memory import AgentMemory
            mem = AgentMemory(collection_name="doc_chunks")
            lesson_results = mem.retrieve(task_desc, n_results=3)
            if lesson_results:
                lesson_text = "\n".join(r.get("content", "") for r in lesson_results if r.get("content"))
                if lesson_text:
                    prompt = f"Relevant past lessons:\n{lesson_text}\n\n" + prompt
                    logger.info(f"[CodeAgent] Injected {len(lesson_results)} past lessons into prompt")
        except Exception as e:
            logger.debug(f"[CodeAgent] Lesson retrieval skipped: {e}")
        try:
            content = chat_with_fallback(
                primary_model=CODE_GEN_MODEL,
                fallback_model="ollama/qwen2.5-coder:7b",
                messages=[
                    {"role": "system", "content": SYSTEM_PROMPT},
                    {"role": "user", "content": prompt},
                ],
                max_tokens=4000,
                temperature=0.1,
            )
            return self._extract_code(content)
        except Exception as e:
            logger.error(f"[CodeAgent] Code generation failed: {e}")
        return ""


    def _execute_code(self, code: str, file_paths: Optional[list] = None):
        import shutil
        files_before = set(self.working_dir.glob("*"))
        script_path = None
        copied_files = []

        # Copy data files to working dir so code can find them locally
        if file_paths:
            for fp in file_paths:
                src = Path(fp)
                if src.exists():
                    dst = self.working_dir / src.name
                    if not dst.exists():
                        try:
                            shutil.copy2(src, dst)
                            copied_files.append(dst)
                        except Exception as e:
                            logger.warning(f"[CodeAgent] Failed to copy {src.name}: {e}")

        try:
            with tempfile.NamedTemporaryFile(mode="w", suffix=".py", dir=self.working_dir, delete=False, encoding="utf-8") as f:
                f.write(code)
                script_path = Path(f.name)
            
            run_kwargs = {
                "args": [sys.executable, str(script_path)],
                "cwd": str(self.working_dir),
                "capture_output": True,
                "text": True,
                "timeout": _PROC_TIMEOUT_S
            }
            if sys.platform != "win32":
                run_kwargs["preexec_fn"] = _sandbox_preexec
            
            result = subprocess.run(**run_kwargs)
            stdout = result.stdout or ""
            stderr = result.stderr or ""
            combined = stdout + (f"\n[stderr]:\n{stderr}" if stderr else "")
            
            if len(combined) > _STDOUT_CHARS:
                combined = combined[:_STDOUT_CHARS] + f"\n\n[OUTPUT TRUNCATED]"
            
            success = result.returncode == 0
        except subprocess.TimeoutExpired:
            return False, f"Execution timed out after {_PROC_TIMEOUT_S}s", []
        except Exception as e:
            return False, f"Execution error: {e}", []
        finally:
            if script_path and script_path.exists():
                try: script_path.unlink()
                except Exception: pass
            # Cleanup copied data files to keep sandbox clean
            for cf in copied_files:
                try: cf.unlink()
                except Exception: pass

        files_after = set(self.working_dir.glob("*"))
        new_files = [f.name for f in (files_after - files_before) if f.is_file() and f.suffix != ".py"]
        return success, combined, new_files

    def _execute_with_retry(self, code: str, task_desc: str, data_context: str, file_paths: Optional[list], max_retries: int) -> dict:
        success, output, files = self._execute_code(code, file_paths)
        if success:
            return {"success": True, "code": code, "output": output, "files_created": files, "error": "", "retries_used": 0}
        for attempt in range(max_retries):
            fix_code = self._generate_fix(code, output, task_desc)
            if fix_code:
                success, output, files = self._execute_code(fix_code, file_paths)
                if success:
                    return {"success": True, "code": fix_code, "output": output, "files_created": files, "error": "", "retries_used": attempt + 1}
                code = fix_code
        return {"success": False, "code": code, "output": output, "files_created": files, "error": output, "retries_used": max_retries}

    def _generate_fix(self, failed_code: str, error_output: str, task_desc: str) -> str:
        prompt = f"""Fix this Python code that failed.\nTask: {task_desc}\nFailed code:\n```python\n{failed_code[:1500]}\n```\nError:\n{error_output[:500]}\nProvide ONE complete fixed Python script in ```python ... ``` fences."""
        try:
            content = chat_with_fallback(
                primary_model=CODE_FIX_MODEL,
                fallback_model="ollama/qwen2.5-coder:7b",
                messages=[
                    {"role": "system", "content": "Fix Python code. Output only the fixed code in ```python``` fences."},
                    {"role": "user", "content": prompt},
                ],
                max_tokens=2000,
                temperature=0.1,
            )
            return self._extract_code(content)
        except Exception as e:
            logger.error(f"[CodeAgent] Code fix failed: {e}")
        return ""

    def _extract_code(self, text: str) -> str:
        import re
        text = re.sub(r'<think>.*?</think>', '', text, flags=re.DOTALL).strip()
        if "```python" in text:
            parts = text.split("```python")
            if len(parts) > 1:
                return parts[1].split("```")[0].strip()
        if "```" in text:
            parts = text.split("```")
            if len(parts) > 1:
                return parts[1].strip()
        return text.strip()

    def _get_relevant_memory(self, query: str) -> str:
        memories = self.memory.retrieve(query, n_results=3)
        if not memories:
            return ""
        return "\n".join(m["content"][:200] for m in memories)
