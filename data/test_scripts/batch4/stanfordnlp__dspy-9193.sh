#!/bin/bash
set -uxo pipefail

# Navigate to testbed
cd /testbed

# Install Deno runtime (CRITICAL REQUIREMENT for these tests)
echo "Installing Deno runtime..."
curl -fsSL https://deno.land/install.sh | sh

# Add Deno to PATH
export DENO_INSTALL="/root/.deno"
export PATH="$DENO_INSTALL/bin:$PATH"

# Verify Deno installation
echo "Verifying Deno installation..."
deno --version

# Checkout the target test files to ensure clean state
git checkout c21f77bc5a3b5a78e2edd55aa28bb5fdf0aad2c8 "tests/predict/test_program_of_thought.py" "tests/primitives/test_python_interpreter.py"

# Apply test patch to update target tests
git apply -v - <<'EOF_114329324912'
diff --git a/tests/mock_interpreter.py b/tests/mock_interpreter.py
new file mode 100644
--- /dev/null
+++ b/tests/mock_interpreter.py
@@ -0,0 +1,132 @@
+"""
+Mock interpreter for testing RLM and other code-executing modules.
+
+This interpreter doesn't actually execute code - it returns scripted responses
+or uses a custom function to generate responses. Useful for:
+- Unit testing without Deno/Pyodide dependencies
+- Testing specific execution paths (errors, FINAL, etc.)
+- Recording what code was submitted for execution
+"""
+
+from typing import Any, Callable
+
+from dspy.primitives.code_interpreter import CodeInterpreterError, FinalAnswerResult
+
+__all__ = ["MockInterpreter"]
+
+
+class MockInterpreter:
+    """Mock interpreter that returns scripted responses.
+
+    Implements the Interpreter protocol for testing purposes.
+
+    Example usage:
+        ```python
+        # Script specific responses
+        mock = MockInterpreter(responses=[
+            "data explored",
+            FinalAnswerResult("42"),
+        ])
+        result1 = mock.execute("print(len(context))")  # Returns "data explored"
+        result2 = mock.execute("FINAL('42')")  # Returns FinalAnswerResult("42")
+
+        # Use custom execution function
+        def custom_exec(code, variables):
+            if "FINAL" in code:
+                return FinalAnswerResult("done")
+            return f"executed: {code[:20]}..."
+
+        mock = MockInterpreter(execute_fn=custom_exec)
+        ```
+    """
+
+    def __init__(
+        self,
+        responses: list[str | FinalAnswerResult | Exception] | None = None,
+        execute_fn: Callable[[str, dict[str, Any]], Any] | None = None,
+        tools: dict[str, Callable[..., str]] | None = None,
+    ):
+        """Initialize the mock interpreter.
+
+        Args:
+            responses: List of responses to return in sequence. Each call to
+                      execute() pops the next response. If an Exception is
+                      in the list, it will be raised.
+            execute_fn: Custom function that receives (code, variables) and
+                       returns the result. Takes precedence over responses.
+            tools: Dictionary mapping tool names to callable functions.
+                   MockInterpreter doesn't use tools, but stores them for protocol compliance.
+        """
+        self.responses = list(responses) if responses else []
+        self.execute_fn = execute_fn
+        self.tools = tools or {}
+        self.call_count = 0
+        self.call_history: list[tuple[str, dict[str, Any]]] = []
+        self._shutdown = False
+
+    def start(self) -> None:
+        pass
+
+    def execute(
+        self,
+        code: str,
+        variables: dict[str, Any] | None = None,
+    ) -> Any:
+        """Execute code and return the next scripted response.
+
+        Args:
+            code: The code that would be executed (recorded in call_history)
+            variables: Variables that would be injected (recorded in call_history)
+
+        Returns:
+            The next response from the responses list, or result from execute_fn
+
+        Raises:
+            CodeInterpreterError: If the interpreter was shutdown, or if an Exception
+                             is in the responses list
+        """
+        if self._shutdown:
+            raise CodeInterpreterError("MockInterpreter has been shutdown")
+
+        variables = variables or {}
+        self.call_history.append((code, variables))
+        self.call_count += 1
+
+        # Custom function takes precedence
+        if self.execute_fn is not None:
+            return self.execute_fn(code, variables)
+
+        # Return scripted responses
+        if not self.responses:
+            return ""
+
+        response = self.responses.pop(0)
+
+        if isinstance(response, Exception):
+            raise response
+
+        return response
+
+    def shutdown(self) -> None:
+        self._shutdown = True
+
+    def reset(self) -> None:
+        """Reset the interpreter state for reuse in tests."""
+        self.call_count = 0
+        self.call_history = []
+        self._shutdown = False
+
+    # Context manager support
+    def __enter__(self) -> "MockInterpreter":
+        return self
+
+    def __exit__(self, *args: Any) -> None:
+        self.shutdown()
+
+    def __call__(
+        self,
+        code: str,
+        variables: dict[str, Any] | None = None,
+    ) -> Any:
+        """Shorthand for execute()."""
+        return self.execute(code, variables)
diff --git a/tests/predict/test_program_of_thought.py b/tests/predict/test_program_of_thought.py
--- a/tests/predict/test_program_of_thought.py
+++ b/tests/predict/test_program_of_thought.py
@@ -22,7 +22,7 @@ def test_pot_code_generation():
         [
             {
                 "reasoning": "Reason_A",
-                "generated_code": "```python\nresult = 1+1\nfinal_answer({'answer': result})\n```",
+                "generated_code": "```python\nresult = 1+1\nFINAL({'answer': result})\n```",
             },
             {"reasoning": "Reason_B", "answer": "2"},
         ]
@@ -62,7 +62,7 @@ def test_pot_support_multiple_fields():
         [
             {
                 "reasoning": "Reason_A",
-                "generated_code": "```python\nmaximum = 6\nminimum = 2\nfinal_answer({'maximum': maximum, 'minimum': minimum})\n```",
+                "generated_code": "```python\nmaximum = 6\nminimum = 2\nFINAL({'maximum': maximum, 'minimum': minimum})\n```",
             },
             {"reasoning": "Reason_B", "maximum": "6", "minimum": "2"},
         ]
@@ -81,11 +81,11 @@ def test_pot_code_generation_with_one_error():
         [
             {
                 "reasoning": "Reason_A",
-                "generated_code": "```python\nresult = 1+0/0\nfinal_answer({'answer': result})\n```",
+                "generated_code": "```python\nresult = 1+0/0\nFINAL({'answer': result})\n```",
             },
             {
                 "reasoning": "Reason_B",
-                "generated_code": "```python\nresult = 1+1\nfinal_answer({'answer': result})\n```",
+                "generated_code": "```python\nresult = 1+1\nFINAL({'answer': result})\n```",
             },
             {"reasoning": "Reason_C", "answer": "2"},
         ]
@@ -104,7 +104,7 @@ def test_pot_code_generation_persistent_errors():
         [
             {
                 "reasoning": "Reason_A",
-                "generated_code": "```python\nresult = 1+0/0\nfinal_answer({'answer': result})\n```",
+                "generated_code": "```python\nresult = 1+0/0\nFINAL({'answer': result})\n```",
             },
         ]
         * max_iters
diff --git a/tests/predict/test_rlm.py b/tests/predict/test_rlm.py
new file mode 100644
--- /dev/null
+++ b/tests/predict/test_rlm.py
@@ -0,0 +1,1077 @@
+"""
+Tests for the RLM (Recursive Language Model) module.
+
+Test organization:
+- Unit tests (no Deno required): MockInterpreter, RLM formatting, signatures
+- Integration tests (@pytest.mark.integration): PythonInterpreter with Deno
+"""
+
+from contextlib import contextmanager
+
+import pytest
+
+from dspy.predict.rlm import RLM
+from dspy.primitives.code_interpreter import CodeInterpreterError, FinalAnswerResult
+from dspy.primitives.prediction import Prediction
+from dspy.primitives.python_interpreter import PythonInterpreter
+from dspy.primitives.repl_types import REPLEntry, REPLHistory, REPLVariable
+from tests.mock_interpreter import MockInterpreter
+
+# ============================================================================
+# Test Helpers and Factories
+# ============================================================================
+
+
+def make_mock_predictor(responses: list[dict], async_mode: bool = False):
+    """Factory for mock predictors with scripted responses.
+
+    Args:
+        responses: List of dicts with keys like 'reasoning', 'code'.
+        async_mode: If True, returns a predictor with acall() instead of __call__().
+    """
+
+    class MockPredictor:
+        def __init__(self):
+            self.idx = 0
+
+        def _next_response(self):
+            result = responses[self.idx % len(responses)]
+            self.idx += 1
+            return Prediction(**result)
+
+        def __call__(self, **kwargs):
+            return self._next_response()
+
+        async def acall(self, **kwargs):
+            return self._next_response()
+
+    return MockPredictor()
+
+
+@contextmanager
+def dummy_lm_context(responses: list[dict]):
+    """Context manager for DummyLM setup."""
+    import dspy
+    from dspy.utils.dummies import DummyLM
+
+    lm = DummyLM(responses)
+    with dspy.context(lm=lm):
+        yield lm
+
+
+# Common test tools
+def echo_tool(text: str = "") -> str:
+    """Echo the input text."""
+    return f"Echo: {text}"
+
+
+def add_tool(a: int = 0, b: int = 0) -> str:
+    """Add two numbers."""
+    return str(a + b)
+
+
+def multiply_tool(a: int = 0, b: int = 0) -> str:
+    """Multiply two numbers."""
+    return str(a * b)
+
+# ============================================================================
+# Unit Tests: MockInterpreter
+# ============================================================================
+
+
+class TestMockInterpreter:
+    """Unit tests for MockInterpreter."""
+
+    def test_scripted_responses(self):
+        """Test that MockInterpreter returns scripted responses in order."""
+        mock = MockInterpreter(responses=["first", "second", "third"])
+        assert mock.execute("code1") == "first"
+        assert mock.execute("code2") == "second"
+        assert mock.execute("code3") == "third"
+
+    def test_returns_final_answer_result(self):
+        """Test that MockInterpreter can return FinalAnswerResult."""
+        mock = MockInterpreter(responses=["exploring", FinalAnswerResult("42")])
+        assert mock.execute("print(len(data))") == "exploring"
+        result = mock.execute("FINAL('42')")
+        assert isinstance(result, FinalAnswerResult)
+        assert result.answer == "42"
+
+    def test_raises_exception_from_responses(self):
+        """Test that MockInterpreter raises exceptions from responses."""
+        mock = MockInterpreter(responses=["ok", CodeInterpreterError("undefined variable")])
+        assert mock.execute("code1") == "ok"
+        with pytest.raises(CodeInterpreterError, match="undefined variable"):
+            mock.execute("code2")
+
+    def test_records_call_history(self):
+        """Test that MockInterpreter records call history for test assertions."""
+        mock = MockInterpreter(responses=["resp"])
+        mock.execute("print(1)", variables={"x": 10})
+        assert mock.call_history == [("print(1)", {"x": 10})]
+
+
+# ============================================================================
+# Unit Tests: RLM Module (no interpreter needed)
+# ============================================================================
+
+
+class TestRLMInitialization:
+    """Tests for RLM module initialization."""
+
+    def test_basic_initialization(self):
+        """Test RLM module initializes correctly with signature."""
+        rlm = RLM("context, query -> answer", max_iterations=5)
+        assert rlm.max_iterations == 5
+        assert rlm.generate_action is not None
+        assert rlm.extract is not None
+        assert rlm.tools == {}  # No user tools provided
+        assert "context" in rlm.signature.input_fields
+        assert "query" in rlm.signature.input_fields
+        assert "answer" in rlm.signature.output_fields
+
+    def test_custom_signature(self):
+        """Test RLM with custom signature."""
+        rlm = RLM("document, question -> summary, key_facts", max_iterations=5)
+        assert "document" in rlm.signature.input_fields
+        assert "question" in rlm.signature.input_fields
+        assert "summary" in rlm.signature.output_fields
+        assert "key_facts" in rlm.signature.output_fields
+
+    def test_custom_tools(self):
+        """Test RLM with custom tools."""
+        def custom_tool(x: str = "") -> str:
+            return x.upper()
+
+        rlm = RLM("context -> answer", max_iterations=5, tools={"custom_tool": custom_tool})
+        assert "custom_tool" in rlm.tools
+        assert len(rlm.tools) == 1  # Only user tools, not internal llm_query/llm_query_batched
+
+    @pytest.mark.parametrize("tool_name", ["invalid-name", "123start"])
+    def test_tool_validation_invalid_identifier(self, tool_name):
+        """Test RLM rejects tool names that aren't valid Python identifiers."""
+        def my_tool() -> str:
+            return "result"
+
+        with pytest.raises(ValueError, match="must be a valid Python identifier"):
+            RLM("context -> answer", tools={tool_name: my_tool})
+
+    @pytest.mark.parametrize("tool_name", ["llm_query", "FINAL", "print"])
+    def test_tool_validation_reserved_names(self, tool_name):
+        """Test RLM rejects tool names that conflict with built-in functions."""
+        def my_tool() -> str:
+            return "result"
+
+        with pytest.raises(ValueError, match="conflicts with built-in"):
+            RLM("context -> answer", tools={tool_name: my_tool})
+
+    @pytest.mark.parametrize("invalid_value", ["not a function", 123])
+    def test_tool_validation_not_callable(self, invalid_value):
+        """Test RLM rejects tools that aren't callable."""
+        with pytest.raises(TypeError, match="must be callable"):
+            RLM("context -> answer", tools={"my_tool": invalid_value})
+
+    def test_optional_parameters(self):
+        """Test RLM optional parameters and their defaults."""
+        import dspy
+
+        # Test defaults
+        rlm = RLM("context -> answer")
+        assert rlm.max_llm_calls == 50
+        assert rlm.sub_lm is None
+        assert rlm._interpreter is None
+
+        # Test custom values
+        mock = MockInterpreter()
+        mock_lm = dspy.LM("openai/gpt-4o-mini")
+        rlm = RLM("context -> answer", max_llm_calls=100, sub_lm=mock_lm, interpreter=mock)
+        assert rlm.max_llm_calls == 100
+        assert rlm.sub_lm is mock_lm
+        assert rlm._interpreter is mock
+
+    def test_forward_validates_required_inputs(self):
+        """Test that forward() raises ValueError for missing required inputs."""
+        mock = MockInterpreter(responses=["result"])
+
+        # Single missing input
+        rlm = RLM("context, query -> answer", max_iterations=3, interpreter=mock)
+        with pytest.raises(ValueError, match="Missing required input"):
+            rlm.forward(context="some context")  # Missing 'query'
+
+        # Multiple missing inputs - all should be reported
+        rlm = RLM("a, b, c -> answer", max_iterations=3, interpreter=mock)
+        with pytest.raises(ValueError) as exc_info:
+            rlm.forward(a="only a")  # Missing 'b' and 'c'
+        assert "b" in str(exc_info.value)
+        assert "c" in str(exc_info.value)
+
+    def test_batched_query_errors_have_clear_markers(self):
+        """Test that errors in llm_query_batched are prefixed with [ERROR]."""
+        from unittest.mock import MagicMock
+
+        mock_lm = MagicMock()
+        mock_lm.side_effect = RuntimeError("LM failed")
+
+        rlm = RLM("context -> answer", max_llm_calls=10, sub_lm=mock_lm)
+        tools = rlm._make_llm_tools()
+
+        results = tools["llm_query_batched"](prompts=["test prompt"])
+        assert len(results) == 1
+        assert results[0].startswith("[ERROR]")
+        assert "LM failed" in results[0]
+
+    def test_tools_call_counter_is_thread_safe(self):
+        """Test that the LLM call counter is thread-safe for concurrent llm_query_batched calls.
+
+        The call counter must be protected by a lock since llm_query_batched uses
+        ThreadPoolExecutor for concurrent execution.
+        """
+        from concurrent.futures import ThreadPoolExecutor
+        from unittest.mock import MagicMock
+
+        mock_lm = MagicMock()
+        mock_lm.return_value = ["response"]
+
+        rlm = RLM("context -> answer", max_llm_calls=10, sub_lm=mock_lm)
+        tools = rlm._make_llm_tools()
+
+        call_count = [0]
+        errors = []
+
+        def make_call():
+            try:
+                tools["llm_query"](prompt="test")
+                call_count[0] += 1
+            except RuntimeError as e:
+                errors.append(e)
+
+        with ThreadPoolExecutor(max_workers=5) as executor:
+            futures = [executor.submit(make_call) for _ in range(10)]
+            for f in futures:
+                f.result()
+
+        assert call_count[0] == 10, f"Expected 10 successful calls, got {call_count[0]}"
+        assert len(errors) == 0, f"Unexpected errors: {errors}"
+
+        with pytest.raises(RuntimeError, match="LLM call limit exceeded"):
+            tools["llm_query"](prompt="one more")
+
+
+class TestRLMFormatting:
+    """Tests for RLM formatting helpers."""
+
+    def test_format_history(self):
+        """Test history formatting using REPLHistory."""
+        history = REPLHistory()
+        history = history.append(reasoning="Need to check the data", code="print(1)", output="1")
+        history = history.append(reasoning="Now calculate", code="x = 2", output="")
+        formatted = history.format()
+        assert "Step 1" in formatted
+        assert "Step 2" in formatted
+        assert "print(1)" in formatted
+        assert "Need to check" in formatted
+
+    def test_format_history_empty(self):
+        """Test history formatting with empty history."""
+        history = REPLHistory()
+        formatted = history.format()
+        assert "have not interacted with the REPL" in formatted
+
+    def test_action_signature_has_iteration_field(self):
+        """Test action signature includes iteration input field."""
+        rlm = RLM("context -> answer")
+        action_sig = rlm.generate_action.signature
+        assert "iteration" in action_sig.input_fields
+
+    def test_format_output(self):
+        """Test output formatting."""
+        rlm = RLM("context -> answer")
+        formatted = rlm._format_output("output text")
+        assert "output text" in formatted
+
+    def test_format_output_empty(self):
+        """Test output formatting with empty output."""
+        rlm = RLM("context -> answer")
+        formatted = rlm._format_output("")
+        assert "no output" in formatted.lower()
+
+    def test_format_output_truncation(self):
+        """Test that long output is truncated."""
+        rlm = RLM("context -> answer", max_output_chars=100)
+        formatted = rlm._format_output("x" * 200)
+        assert "truncated" in formatted.lower()
+
+    def test_format_variable_info_string(self):
+        """Test variable info formatting for string value using REPLVariable."""
+        var = REPLVariable.from_value("context", "Hello world", preview_chars=5)
+        formatted = var.format()
+        assert "Variable: `context`" in formatted
+        assert "Type: str" in formatted
+        assert "11" in formatted  # length
+        assert "Hello" in formatted
+        assert "..." in formatted  # truncation indicator
+
+    def test_format_variable_info_dict(self):
+        """Test variable info formatting for dict value using REPLVariable."""
+        var = REPLVariable.from_value("data", {"key": "value"})
+        formatted = var.format()
+        assert "Variable: `data`" in formatted
+        assert "Type: dict" in formatted
+        assert "key" in formatted
+
+    def test_build_variables_multiple(self):
+        """Test building multiple variables."""
+        rlm = RLM("context, query -> answer")
+        variables = rlm._build_variables(
+            context="Hello world",
+            query="What is this?"
+        )
+        assert len(variables) == 2
+        formatted = "\n\n".join(v.format() for v in variables)
+        assert "Variable: `context`" in formatted
+        assert "Variable: `query`" in formatted
+        assert "Hello world" in formatted
+        assert "What is this?" in formatted
+
+
+class TestREPLTypes:
+    """Tests for the REPL type classes."""
+
+    def test_repl_history_immutability(self):
+        """Test that REPLHistory.append() returns new instance."""
+        h1 = REPLHistory()
+        h2 = h1.append(code="print(1)", output="1")
+        assert len(h1) == 0  # Original unchanged
+        assert len(h2) == 1  # New has entry
+
+    def test_repl_history_len_iter_bool(self):
+        """Test REPLHistory list-like interface."""
+        h = REPLHistory()
+        assert len(h) == 0
+        assert not bool(h)
+
+        h = h.append(code="x = 1", output="")
+        h = h.append(code="x = 2", output="")
+        assert len(h) == 2
+        assert bool(h)
+
+        codes = [e.code for e in h]
+        assert codes == ["x = 1", "x = 2"]
+
+    def test_repl_entry_format(self):
+        """Test REPLEntry formatting."""
+        entry = REPLEntry(reasoning="test reason", code="print(1)", output="1")
+        formatted = entry.format(index=0)
+        assert "Step 1" in formatted
+        assert "test reason" in formatted
+        assert "print(1)" in formatted
+        assert "1" in formatted
+
+    def test_repl_entry_format_truncation(self):
+        """Test REPLEntry output truncation."""
+        entry = REPLEntry(code="print('x' * 1000)", output="x" * 1000)
+        formatted = entry.format(index=0, max_output_chars=50)
+        assert "truncated" in formatted
+
+    def test_repl_variable_from_value(self):
+        """Test REPLVariable.from_value() factory."""
+        var = REPLVariable.from_value("test", "hello world")
+        assert var.name == "test"
+        assert var.type_name == "str"
+        assert var.total_length == 11
+        assert "hello world" in var.preview
+
+    def test_repl_variable_truncation(self):
+        """Test REPLVariable preview truncation."""
+        var = REPLVariable.from_value("big", "x" * 1000, preview_chars=50)
+        assert len(var.preview) == 53  # 50 + "..."
+        assert var.preview.endswith("...")
+
+    def test_repl_variable_with_field_info(self):
+        """Test REPLVariable includes desc and constraints from field_info."""
+        import dspy
+
+        # Create a field with description and constraints
+        field = dspy.InputField(desc="The user's question", ge=0, le=100)
+
+        var = REPLVariable.from_value("query", "What is 2+2?", field_info=field)
+        assert var.desc == "The user's question"
+        assert "greater than or equal to" in var.constraints
+
+        # Verify format includes the metadata
+        formatted = var.format()
+        assert "Description: The user's question" in formatted
+        assert "Constraints:" in formatted
+
+    def test_repl_variable_without_field_info(self):
+        """Test REPLVariable works without field_info."""
+        var = REPLVariable.from_value("data", [1, 2, 3])
+        assert var.desc == ""
+        assert var.constraints == ""
+
+        # Format should not include empty desc/constraints lines
+        formatted = var.format()
+        assert "Description:" not in formatted
+        assert "Constraints:" not in formatted
+
+    def test_build_variables_includes_field_metadata(self):
+        """Test _build_variables passes field_info to REPLVariable."""
+        import dspy
+
+        class QASig(dspy.Signature):
+            """Answer questions."""
+            context: str = dspy.InputField(desc="Background information")
+            question: str = dspy.InputField(desc="The question to answer")
+            answer: str = dspy.OutputField()
+
+        rlm = RLM(QASig, max_iterations=3)
+        variables = rlm._build_variables(context="Some text", question="What?")
+
+        # Find the context variable
+        context_var = next(v for v in variables if v.name == "context")
+        assert context_var.desc == "Background information"
+
+        question_var = next(v for v in variables if v.name == "question")
+        assert question_var.desc == "The question to answer"
+
+
+class TestRLMCallMethod:
+    """Tests for RLM __call__ method."""
+
+    def test_call_is_alias_for_forward(self):
+        """Test that __call__ is an alias for forward()."""
+        mock = MockInterpreter(responses=[FinalAnswerResult({"answer": "42"})])
+        rlm = RLM("query -> answer", max_iterations=3, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return answer", "code": 'FINAL("42")'},
+        ])
+
+        result = rlm(query="What is the answer?")
+        assert result.answer == "42"
+
+
+class TestRLMMaxIterationsFallback:
+    """Tests for max_iterations reached and extract fallback."""
+
+    def test_max_iterations_triggers_extract(self):
+        """Test that reaching max_iterations uses extract fallback."""
+        mock = MockInterpreter(responses=[
+            "exploring...",
+            "still exploring...",
+            "more exploring...",
+        ])
+        rlm = RLM("query -> answer", max_iterations=3, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Explore 1", "code": "print('exploring')"},
+            {"reasoning": "Explore 2", "code": "print('exploring')"},
+            {"reasoning": "Explore 3", "code": "print('exploring')"},
+        ])
+        # Mock the extract predictor to return a value
+        rlm.extract = make_mock_predictor([
+            {"answer": "extracted_answer"},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.answer == "extracted_answer"
+        assert result.final_reasoning == "Extract forced final answer"
+
+
+class TestRLMToolExceptions:
+    """Tests for tool exception handling."""
+
+    def test_tool_exception_returns_error_in_output(self):
+        """Test that tool exceptions are caught and returned as errors."""
+        def failing_tool() -> str:
+            raise RuntimeError("Tool failed!")
+
+        mock = MockInterpreter(responses=[
+            CodeInterpreterError("RuntimeError: Tool failed!"),
+            FinalAnswerResult({"answer": "recovered"}),
+        ])
+        rlm = RLM("query -> answer", max_iterations=5, interpreter=mock, tools={"failing_tool": failing_tool})
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Call tool", "code": "failing_tool()"},
+            {"reasoning": "Recover", "code": 'FINAL("recovered")'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.answer == "recovered"
+
+
+class TestRLMDynamicSignature:
+    """Tests for the dynamically built RLM signatures."""
+
+    def test_action_signature_structure(self):
+        """Test action signature has required fields and instructions."""
+        rlm = RLM("document, question -> summary, answer")
+        action_sig = rlm.generate_action.signature
+
+        # Required input/output fields
+        assert "variables_info" in action_sig.input_fields
+        assert "repl_history" in action_sig.input_fields
+        assert "reasoning" in action_sig.output_fields
+        assert "code" in action_sig.output_fields
+
+        # Instructions mention key tools and variables
+        instructions = action_sig.instructions
+        assert "llm_query" in instructions
+        assert "llm_query_batched" in instructions
+        assert "FINAL" in instructions
+        assert "`document`" in instructions
+        assert "`question`" in instructions
+        assert "`summary`" in instructions
+        assert "`answer`" in instructions
+
+    def test_extract_signature_structure(self):
+        """Test extract signature has required fields for all outputs."""
+        rlm = RLM("document, question -> summary, key_facts, confidence")
+        extract_sig = rlm.extract.signature
+        assert "variables_info" in extract_sig.input_fields
+        assert "repl_history" in extract_sig.input_fields
+        assert "summary" in extract_sig.output_fields
+        assert "key_facts" in extract_sig.output_fields
+        assert "confidence" in extract_sig.output_fields
+
+
+# ============================================================================
+# Integration Tests: PythonInterpreter (require Deno)
+# ============================================================================
+
+
+@pytest.mark.integration
+class TestPythonInterpreter:
+    """Integration tests for the secure sandbox with tool support."""
+
+    def test_start_prewarms_sandbox(self):
+        """Test that start() pre-warms the sandbox."""
+        interp = PythonInterpreter()
+        try:
+            # Before start, deno_process should be None
+            assert interp.deno_process is None
+            # After start, it should be running
+            interp.start()
+            assert interp.deno_process is not None
+            assert interp.deno_process.poll() is None  # Still running
+            # Execute should work
+            result = interp.execute("print(42)")
+            assert "42" in result
+        finally:
+            interp.shutdown()
+
+    def test_start_is_idempotent(self):
+        """Test that start() can be called multiple times safely."""
+        interp = PythonInterpreter()
+        try:
+            interp.start()
+            first_process = interp.deno_process
+            interp.start()  # Second call - should be idempotent
+            assert interp.deno_process is first_process  # Same process
+        finally:
+            interp.shutdown()
+
+    def test_basic_execution(self):
+        """Test basic code execution."""
+        with PythonInterpreter() as interp:
+            result = interp.execute("print(1 + 1)")
+            assert "2" in result
+
+    def test_variable_injection(self):
+        """Test variable injection."""
+        with PythonInterpreter(tools={}) as interp:
+            result = interp.execute(
+                "print(x + y)",
+                variables={"x": 10, "y": 5}
+            )
+            assert "15" in result
+
+    def test_tool_call_kwargs(self):
+        """Test tool call with keyword arguments."""
+        def echo(message: str = "") -> str:
+            return f"Echo: {message}"
+
+        with PythonInterpreter(tools={"echo": echo}) as interp:
+            result = interp.execute('print(echo(message="hello"))')
+            assert "Echo: hello" in result
+
+    def test_tool_call_positional(self):
+        """Test tool call with positional arguments."""
+        def greet(name: str) -> str:
+            return f"Hello: {name}"
+
+        with PythonInterpreter(tools={"greet": greet}) as interp:
+            result = interp.execute('print(greet("world"))')
+            assert "Hello: world" in result
+
+    def test_multiple_tools(self):
+        """Test multiple tools."""
+        def add(a: int = 0, b: int = 0) -> str:
+            return str(a + b)
+
+        def multiply(a: int = 0, b: int = 0) -> str:
+            return str(a * b)
+
+        with PythonInterpreter(tools={"add": add, "multiply": multiply}) as interp:
+            result = interp.execute("""
+sum_result = add(a=3, b=4)
+prod_result = multiply(a=3, b=4)
+print(f"Sum: {sum_result}, Product: {prod_result}")
+""")
+            assert "Sum: 7" in result
+            assert "Product: 12" in result
+
+    def test_tool_returns_list(self):
+        """Test tool that returns a list (like llm_query_batched)."""
+        def batch_process(items: list | None = None) -> list:
+            items = items or []
+            return [f"processed_{item}" for item in items]
+
+        with PythonInterpreter(tools={"batch_process": batch_process}) as interp:
+            result = interp.execute("""
+results = batch_process(items=["a", "b", "c"])
+print(f"Type: {type(results).__name__}")
+print(f"Length: {len(results)}")
+print(f"First: {results[0]}")
+print(f"All: {results}")
+""")
+            assert "Type: list" in result
+            assert "Length: 3" in result
+            assert "First: processed_a" in result
+
+    def test_tool_returns_dict(self):
+        """Test tool that returns a dict."""
+        def get_info() -> dict:
+            return {"name": "test", "count": 42}
+
+        with PythonInterpreter(tools={"get_info": get_info}) as interp:
+            result = interp.execute("""
+info = get_info()
+print(f"Type: {type(info).__name__}")
+print(f"Name: {info['name']}")
+print(f"Count: {info['count']}")
+""")
+            assert "Type: dict" in result
+            assert "Name: test" in result
+            assert "Count: 42" in result
+
+    def test_state_persists(self):
+        """Test that state persists across executions."""
+        with PythonInterpreter(tools={}) as interp:
+            interp.execute("x = 10")
+            result = interp.execute("print(x + 5)")
+            assert "15" in result
+
+    def test_syntax_error(self):
+        """Test syntax error handling."""
+        with PythonInterpreter(tools={}) as interp:
+            with pytest.raises(SyntaxError):
+                interp.execute("def incomplete(")
+
+    def test_runtime_error(self):
+        """Test runtime error handling."""
+        with PythonInterpreter(tools={}) as interp:
+            with pytest.raises(CodeInterpreterError):
+                interp.execute("undefined_variable")
+
+
+@pytest.mark.integration
+class TestSandboxSecurity:
+    """Integration tests for sandbox security restrictions."""
+
+    def test_no_network_access(self):
+        """Test that network access is blocked."""
+        with PythonInterpreter(tools={}) as interp:
+            with pytest.raises(CodeInterpreterError) as exc_info:
+                interp.execute("""
+from pyodide.http import pyfetch
+import asyncio
+asyncio.get_event_loop().run_until_complete(pyfetch("https://example.com"))
+""")
+            assert "net access" in str(exc_info.value).lower() or "allow-net" in str(exc_info.value).lower()
+
+    def test_imports_work(self):
+        """Test that standard library imports work."""
+        with PythonInterpreter(tools={}) as interp:
+            result = interp.execute("""
+import json
+import re
+from collections import Counter
+data = {"key": "value"}
+print(json.dumps(data))
+""")
+            assert "key" in result
+
+
+# ============================================================================
+# Unit Tests: RLM with MockInterpreter (no Deno required)
+# ============================================================================
+
+
+class TestRLMAsyncMock:
+    """Unit tests for RLM aforward() using MockInterpreter (no Deno required)."""
+
+    @pytest.mark.asyncio
+    async def test_aforward_basic(self):
+        """Test aforward() returns Prediction with expected output (MockInterpreter)."""
+        mock = MockInterpreter(responses=[FinalAnswerResult({"answer": "42"})])
+        rlm = RLM("query -> answer", max_iterations=3, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return answer", "code": 'FINAL("42")'},
+        ])
+
+        result = await rlm.aforward(query="What is the answer?")
+        assert result.answer == "42"
+
+    @pytest.mark.asyncio
+    async def test_aforward_int_output_mock(self):
+        """Test aforward() returns int when signature expects int (MockInterpreter)."""
+        mock = MockInterpreter(responses=[FinalAnswerResult({"count": 42})])
+        rlm = RLM("query -> count: int", max_iterations=3, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return count", "code": "FINAL(42)"},
+        ])
+
+        result = await rlm.aforward(query="count items")
+        assert result.count == 42
+        assert isinstance(result.count, int)
+
+    @pytest.mark.asyncio
+    async def test_aforward_multi_iteration_mock(self):
+        """Test aforward() handles multiple iterations before FINAL (MockInterpreter)."""
+        mock = MockInterpreter(responses=[
+            "explored data",
+            FinalAnswerResult({"answer": "done"}),
+        ])
+        rlm = RLM("query -> answer", max_iterations=5, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Explore first", "code": "print('exploring')"},
+            {"reasoning": "Now finish", "code": 'FINAL("done")'},
+        ])
+
+        result = await rlm.aforward(query="test")
+        assert result.answer == "done"
+
+
+class TestRLMTypeCoercionMock:
+    """Unit tests for RLM type coercion using MockInterpreter (no Deno required)."""
+
+    @pytest.mark.parametrize("output_field,output_type,final_value,code,expected", [
+        ("count", "int", 42, "FINAL(42)", 42),
+        ("score", "float", 3.14, "FINAL(3.14)", 3.14),
+        ("valid", "bool", True, "FINAL(True)", True),
+        ("numbers", "list[int]", [1, 2, 3], "FINAL([1, 2, 3])", [1, 2, 3]),
+        ("answer", "Literal['yes', 'no']", "yes", 'FINAL("yes")', "yes"),
+    ])
+    def test_type_coercion(self, output_field, output_type, final_value, code, expected):
+        """Test RLM type coercion for various types (MockInterpreter)."""
+        mock = MockInterpreter(responses=[FinalAnswerResult({output_field: final_value})])
+        rlm = RLM(f"query -> {output_field}: {output_type}", max_iterations=3, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return value", "code": code},
+        ])
+
+        result = rlm.forward(query="test")
+        assert getattr(result, output_field) == expected
+
+    def test_type_error_retries(self):
+        """Test RLM retries when type validation fails (MockInterpreter)."""
+        mock = MockInterpreter(responses=[
+            FinalAnswerResult({"answer": "maybe"}),  # Invalid for Literal
+            FinalAnswerResult({"answer": "yes"}),    # Valid
+        ])
+        rlm = RLM("query -> answer: Literal['yes', 'no']", max_iterations=5, interpreter=mock)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Try maybe", "code": 'FINAL("maybe")'},
+            {"reasoning": "Try yes", "code": 'FINAL("yes")'},
+        ])
+
+        result = rlm.forward(query="is it yes?")
+        assert result.answer == "yes"
+
+
+# ============================================================================
+# Integration Tests: RLM Type Coercion with PythonInterpreter
+# ============================================================================
+
+
+@pytest.mark.integration
+class TestRLMTypeCoercion:
+    """Tests for RLM type coercion through full forward pass with PythonInterpreter.
+
+    Note: These tests let RLM create its own PythonInterpreter so it can register
+    typed output_fields for FINAL based on the signature.
+    """
+
+    @pytest.mark.parametrize("output_field,output_type,code,expected,expected_type", [
+        ("count", "int", "FINAL(42)", 42, int),
+        ("score", "float", "FINAL(3.14)", 3.14, float),
+        ("valid", "bool", "FINAL(True)", True, bool),
+        ("numbers", "list[int]", "FINAL([1, 2, 3])", [1, 2, 3], list),
+        ("data", "dict[str, str]", 'FINAL({"key": "value"})', {"key": "value"}, dict),
+        ("answer", "Literal['yes', 'no']", 'FINAL("yes")', "yes", str),
+    ])
+    def test_type_coercion(self, output_field, output_type, code, expected, expected_type):
+        """Test RLM type coercion for various types with PythonInterpreter."""
+        rlm = RLM(f"query -> {output_field}: {output_type}", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return value", "code": code},
+        ])
+
+        result = rlm.forward(query="test")
+        assert getattr(result, output_field) == expected
+        assert isinstance(getattr(result, output_field), expected_type)
+
+    def test_final_var_extracts_typed_value(self):
+        """Test RLM FINAL_VAR correctly extracts typed value."""
+        rlm = RLM("query -> count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Compute and return", "code": 'result = 42\nFINAL_VAR("result")'},
+        ])
+
+        result = rlm.forward(query="count items")
+        assert result.count == 42
+        assert isinstance(result.count, int)
+
+
+# ============================================================================
+# Integration Tests: RLM Multiple Output Fields
+# ============================================================================
+
+
+@pytest.mark.integration
+class TestRLMMultipleOutputs:
+    """Tests for signatures with multiple typed output fields.
+
+    Tests FINAL() and FINAL_VAR() calling patterns with multi-output signatures.
+    """
+
+    def test_multi_output_final_kwargs(self):
+        """FINAL(field1=val1, field2=val2) with keyword args."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return both outputs", "code": 'FINAL(name="alice", count=5)'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "alice"
+        assert result.count == 5
+        assert isinstance(result.count, int)
+
+    def test_multi_output_final_positional(self):
+        """FINAL(val1, val2) with positional args mapped to field order."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return both outputs positionally", "code": 'FINAL("bob", 10)'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "bob"
+        assert result.count == 10
+
+    def test_multi_output_three_fields(self):
+        """Signature with 3+ output fields of different types."""
+        rlm = RLM("query -> name: str, age: int, active: bool", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return all three", "code": 'FINAL(name="carol", age=30, active=True)'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "carol"
+        assert result.age == 30
+        assert result.active is True
+
+    def test_multi_output_final_missing_field_errors(self):
+        """FINAL() with missing field should return error in output."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Missing count field", "code": 'FINAL(name="alice")'},
+            {"reasoning": "Now provide both", "code": 'FINAL(name="alice", count=5)'},
+        ])
+
+        # RLM should retry after getting error for missing field
+        result = rlm.forward(query="test")
+        assert result.name == "alice"
+        assert result.count == 5
+
+    def test_multi_output_final_var(self):
+        """FINAL_VAR("var1", "var2") maps variables to output fields."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Use FINAL_VAR", "code": 'n = "dave"\nc = 15\nFINAL_VAR("n", "c")'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "dave"
+        assert result.count == 15
+
+    def test_multi_output_final_var_wrong_count_errors(self):
+        """FINAL_VAR with wrong number of args should error and retry."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Wrong arg count", "code": 'n = "eve"\nFINAL_VAR("n")'},  # Missing second arg
+            {"reasoning": "Now correct", "code": 'FINAL(name="eve", count=20)'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "eve"
+        assert result.count == 20
+
+    def test_multi_output_final_var_undefined_errors(self):
+        """FINAL_VAR with undefined variable should error and retry."""
+        rlm = RLM("query -> name: str, count: int", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Undefined var", "code": 'n = "frank"\nFINAL_VAR("n", "undefined_var")'},
+            {"reasoning": "Now correct", "code": 'FINAL(name="frank", count=25)'},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.name == "frank"
+        assert result.count == 25
+
+    def test_multi_output_type_coercion(self):
+        """Each output field is coerced to its declared type."""
+        rlm = RLM("query -> count: int, ratio: float, flag: bool", max_iterations=3)
+        rlm.generate_action = make_mock_predictor([
+            {"reasoning": "Return mixed types", "code": "FINAL(count=42, ratio=3.14, flag=True)"},
+        ])
+
+        result = rlm.forward(query="test")
+        assert result.count == 42
+        assert isinstance(result.count, int)
+        assert result.ratio == 3.14
+        assert isinstance(result.ratio, float)
+        assert result.flag is True
+        assert isinstance(result.flag, bool)
+
+
+# ============================================================================
+# Integration Tests: RLM with DummyLM and PythonInterpreter
+# ============================================================================
+
+
+@pytest.mark.integration
+class TestRLMWithDummyLM:
+    """End-to-end tests using DummyLM with RLM and PythonInterpreter.
+
+    Note: These tests let RLM create its own PythonInterpreter so it can register
+    typed output_fields for FINAL based on the signature.
+    """
+
+    def test_simple_computation_e2e(self):
+        """Test full RLM pipeline: DummyLM -> RLM -> PythonInterpreter -> result."""
+        with dummy_lm_context([
+            {"reasoning": "I need to compute 2 + 3", "code": "result = 2 + 3\nFINAL(result)"},
+        ]):
+            rlm = RLM("query -> answer: int", max_iterations=3)
+            result = rlm.forward(query="What is 2 + 3?")
+
+            assert result.answer == 5
+            assert isinstance(result.answer, int)
+
+    def test_multi_turn_computation_e2e(self):
+        """Test RLM with multiple turns before FINAL."""
+        with dummy_lm_context([
+            {"reasoning": "First explore the data", "code": "x = 10\nprint(f'x = {x}')"},
+            {"reasoning": "Now compute and return", "code": "y = x * 2\nFINAL(y)"},
+        ]):
+            rlm = RLM("query -> answer: int", max_iterations=5)
+            result = rlm.forward(query="Double ten")
+
+            assert result.answer == 20
+            assert len(result.trajectory) == 2
+
+    def test_with_input_variables_e2e(self):
+        """Test RLM with input variables passed to sandbox."""
+        with dummy_lm_context([
+            {"reasoning": "Sum the numbers in the list", "code": "FINAL(sum(numbers))"},
+        ]):
+            rlm = RLM("numbers: list[int] -> total: int", max_iterations=3)
+            result = rlm.forward(numbers=[1, 2, 3, 4, 5])
+
+            assert result.total == 15
+
+    def test_with_tool_e2e(self):
+        """Test RLM calling a host-side tool through the sandbox."""
+        def lookup(key: str) -> str:
+            return {"apple": "red", "banana": "yellow"}.get(key, "unknown")
+
+        with dummy_lm_context([
+            {"reasoning": "Look up the color of apple", "code": 'color = lookup(key="apple")\nFINAL(color)'},
+        ]):
+            rlm = RLM("fruit -> color: str", max_iterations=3, tools={"lookup": lookup})
+            result = rlm.forward(fruit="apple")
+
+            assert result.color == "red"
+
+    @pytest.mark.asyncio
+    async def test_aforward_simple_computation_e2e(self):
+        """Test aforward() full pipeline: DummyLM -> RLM -> PythonInterpreter -> result."""
+        with dummy_lm_context([
+            {"reasoning": "I need to compute 2 + 3", "code": "result = 2 + 3\nFINAL(result)"},
+        ]):
+            rlm = RLM("query -> answer: int", max_iterations=3)
+            result = await rlm.aforward(query="What is 2 + 3?")
+
+            assert result.answer == 5
+            assert isinstance(result.answer, int)
+
+    @pytest.mark.asyncio
+    async def test_aforward_multi_turn_e2e(self):
+        """Test aforward() with multiple turns before FINAL."""
+        with dummy_lm_context([
+            {"reasoning": "First explore the data", "code": "x = 10\nprint(f'x = {x}')"},
+            {"reasoning": "Now compute and return", "code": "y = x * 2\nFINAL(y)"},
+        ]):
+            rlm = RLM("query -> answer: int", max_iterations=5)
+            result = await rlm.aforward(query="Double ten")
+
+            assert result.answer == 20
+            assert len(result.trajectory) == 2
+
+    @pytest.mark.asyncio
+    async def test_aforward_with_input_variables_e2e(self):
+        """Test aforward() with input variables passed to sandbox."""
+        with dummy_lm_context([
+            {"reasoning": "Sum the numbers in the list", "code": "FINAL(sum(numbers))"},
+        ]):
+            rlm = RLM("numbers: list[int] -> total: int", max_iterations=3)
+            result = await rlm.aforward(numbers=[1, 2, 3, 4, 5])
+
+            assert result.total == 15
+
+
+# ============================================================================
+# Integration Tests: RLM with real LM (require API key and Deno)
+# ============================================================================
+
+
+@pytest.mark.skip(reason="Requires actual LM and Deno - run manually")
+class TestRLMIntegration:
+    """Integration tests that require a configured LM."""
+
+    def test_simple_computation(self):
+        """Test RLM on simple computation."""
+        import dspy
+        dspy.configure(lm=dspy.LM("openai/gpt-4o-mini"))
+
+        rlm = RLM("context, query -> answer", max_iterations=5)
+        result = rlm(
+            context={"numbers": [1, 2, 3, 4, 5]},
+            query="What is the sum of the numbers?"
+        )
+        assert "15" in result.answer
+
+    def test_with_llm_query(self):
+        """Test RLM using the llm_query tool."""
+        import dspy
+        dspy.configure(lm=dspy.LM("openai/gpt-4o-mini"))
+
+        rlm = RLM("context, query -> answer", max_iterations=5)
+        result = rlm(
+            context="The quick brown fox jumps over the lazy dog.",
+            query="Use llm_query to describe what animal is mentioned as lazy."
+        )
+        assert "dog" in result.answer.lower()
+
+
+if __name__ == "__main__":
+    pytest.main([__file__, "-v"])
diff --git a/tests/primitives/test_python_interpreter.py b/tests/primitives/test_python_interpreter.py
--- a/tests/primitives/test_python_interpreter.py
+++ b/tests/primitives/test_python_interpreter.py
@@ -4,7 +4,8 @@
 
 import pytest
 
-from dspy.primitives.python_interpreter import InterpreterError, PythonInterpreter
+from dspy.primitives.code_interpreter import CodeInterpreterError, FinalAnswerResult
+from dspy.primitives.python_interpreter import PythonInterpreter
 
 # This test suite requires deno to be installed. Please install deno following https://docs.deno.com/runtime/getting_started/installation/
 if shutil.which("deno") is None:
@@ -32,6 +33,18 @@ def test_user_variable_definitions():
         assert result == 5, "User variable assignment should work"
 
 
+def test_rejects_python_keywords_as_variable_names():
+    """Test that Python keywords are rejected as variable names."""
+    with PythonInterpreter() as interpreter:
+        # These are valid Python identifiers but reserved keywords
+        # Using them as variable names would cause syntax errors
+        keywords_to_test = ["for", "class", "import", "def", "return", "if", "while"]
+
+        for keyword in keywords_to_test:
+            with pytest.raises(CodeInterpreterError, match="Invalid variable name"):
+                interpreter.execute("print(x)", variables={keyword: 42})
+
+
 def test_failure_syntax_error():
     with PythonInterpreter() as interpreter:
         code = "+++"
@@ -42,26 +55,29 @@ def test_failure_syntax_error():
 def test_failure_zero_division():
     with PythonInterpreter() as interpreter:
         code = "1+0/0"
-        with pytest.raises(InterpreterError, match="ZeroDivisionError"):
+        with pytest.raises(CodeInterpreterError, match="ZeroDivisionError"):
             interpreter.execute(code)
 
 
 def test_exception_args():
     with PythonInterpreter() as interpreter:
         token = random.randint(1, 10**9)
         code = f"raise ValueError({token})"
-        with pytest.raises(InterpreterError, match=rf"ValueError: \[{token}\]"):
+        with pytest.raises(CodeInterpreterError, match=rf"ValueError: \[{token}\]"):
             interpreter.execute(code)
 
 
-def test_final_answer_trick():
+def test_final_with_list():
+    """Test FINAL() with a list argument returns FinalAnswerResult with dict format."""
+
     with PythonInterpreter() as interpreter:
         token = random.randint(1, 10**9)
-        code = f"final_answer('The result is', {token})"
+        code = f"FINAL(['The result is', {token}])"
         result = interpreter(code)
 
-        # They should maintain the same order
-        assert result == ["The result is", token], "The returned results are differ, `final_answer` trick doesn't work"
+        assert isinstance(result, FinalAnswerResult)
+        # FINAL now always returns a dict with "answer" key for single-output default
+        assert result.answer == {"answer": ["The result is", token]}
 
 def test_enable_env_vars_flag():
     os.environ["FOO_TEST_ENV"] = "test_value"
@@ -158,7 +174,7 @@ def test_enable_net_flag():
             f"resp = await js.fetch({test_url!r})\n"
             "resp.status"
         )
-        with pytest.raises(InterpreterError, match="PythonError"):
+        with pytest.raises(CodeInterpreterError, match="PythonError"):
             interpreter.execute(code)
 
     with PythonInterpreter(enable_network_access=["example.com"]) as interpreter:
@@ -202,3 +218,192 @@ def test_interpreter_security_filesystem_access(tmp_path):
         output = interpreter(malicious_code)
         assert secret_content in output
 
+
+def test_tools_dict_is_copied():
+    """Test that tools dict is defensively copied, not stored by reference."""
+    tools = {"my_tool": lambda: "result"}
+    sandbox = PythonInterpreter(tools=tools)
+
+    # Modify the original dict after construction
+    tools["new_tool"] = lambda: "new"
+
+    # The sandbox should not see the new tool
+    assert "new_tool" not in sandbox.tools
+
+
+def test_serialize_tuple():
+    """Test that tuples can be serialized as variables."""
+    with PythonInterpreter() as interpreter:
+        result = interpreter.execute("x", variables={"x": (1, 2, 3)})
+        assert result == [1, 2, 3]  # Tuples become lists in JSON
+
+
+def test_serialize_set():
+    """Test that sets can be serialized as variables."""
+    with PythonInterpreter() as interpreter:
+        result = interpreter.execute("sorted(x)", variables={"x": {3, 1, 2}})
+        assert result == [1, 2, 3]
+
+
+def test_serialize_set_mixed_types():
+    """Test that sets with mixed types can be serialized (fallback to list)."""
+    with PythonInterpreter() as interpreter:
+        # Mixed types can't be sorted, so they serialize as a list in arbitrary order
+        # We verify the list contains the expected elements
+        result = interpreter.execute("x", variables={"x": {1, "a"}})
+        assert isinstance(result, list)
+        assert set(result) == {1, "a"}
+
+
+def test_deno_command_dict_raises_type_error():
+    """Test that passing a dict as deno_command raises TypeError."""
+    with pytest.raises(TypeError, match="deno_command must be a list"):
+        PythonInterpreter(deno_command={"invalid": "dict"})
+
+
+# =============================================================================
+# Typed Tool Signature Tests
+# =============================================================================
+
+def test_tool_with_typed_signature():
+    """Test that tools get proper typed signatures from inspect."""
+    def my_tool(query: str, limit: int = 10) -> str:
+        return f"searched '{query}' with limit {limit}"
+
+    with PythonInterpreter(tools={"my_tool": my_tool}) as sandbox:
+        # Tool should be callable with typed signature
+        result = sandbox.execute('my_tool(query="test", limit=5)')
+        assert result == "searched 'test' with limit 5"
+
+
+def test_tool_positional_args():
+    """Test that tools work with positional arguments."""
+    def search(query: str, limit: int = 10) -> str:
+        return f"query={query}, limit={limit}"
+
+    with PythonInterpreter(tools={"search": search}) as sandbox:
+        result = sandbox.execute('search("hello")')
+        assert result == "query=hello, limit=10"
+
+
+def test_tool_keyword_args():
+    """Test that tools work with keyword arguments."""
+    def search(query: str, limit: int = 10) -> str:
+        return f"query={query}, limit={limit}"
+
+    with PythonInterpreter(tools={"search": search}) as sandbox:
+        result = sandbox.execute('search(query="hello", limit=5)')
+        assert result == "query=hello, limit=5"
+
+
+def test_tool_default_args():
+    """Test that tool default arguments work correctly."""
+    def greet(name: str, greeting: str = "Hello") -> str:
+        return f"{greeting}, {name}!"
+
+    with PythonInterpreter(tools={"greet": greet}) as sandbox:
+        # Without default
+        result = sandbox.execute('greet("World")')
+        assert result == "Hello, World!"
+
+        # Overriding default
+        result = sandbox.execute('greet("World", "Hi")')
+        assert result == "Hi, World!"
+
+
+# =============================================================================
+# Multi-Output FINAL Tests
+# =============================================================================
+
+def test_final_with_typed_signature():
+    """Test FINAL with typed output signature."""
+
+    output_fields = [
+        {"name": "answer", "type": "str"},
+        {"name": "confidence", "type": "float"},
+    ]
+
+    with PythonInterpreter(output_fields=output_fields) as sandbox:
+        result = sandbox.execute('FINAL(answer="the answer", confidence=0.95)')
+
+        assert isinstance(result, FinalAnswerResult)
+        assert result.answer == {"answer": "the answer", "confidence": 0.95}
+
+
+def test_final_positional_args():
+    """Test FINAL with positional arguments."""
+
+    output_fields = [
+        {"name": "answer", "type": "str"},
+        {"name": "confidence", "type": "float"},
+    ]
+
+    with PythonInterpreter(output_fields=output_fields) as sandbox:
+        result = sandbox.execute('FINAL("the answer", 0.95)')
+
+        assert isinstance(result, FinalAnswerResult)
+        assert result.answer == {"answer": "the answer", "confidence": 0.95}
+
+
+def test_final_var_multi_output():
+    """Test FINAL_VAR with multiple output fields using positional args."""
+
+    output_fields = [
+        {"name": "answer", "type": "str"},
+        {"name": "score", "type": "int"},
+    ]
+
+    with PythonInterpreter(output_fields=output_fields) as sandbox:
+        # Positional args: variable names mapped to output fields in order
+        code = """
+a = "my answer"
+s = 42
+FINAL_VAR("a", "s")
+"""
+        result = sandbox.execute(code)
+
+        assert isinstance(result, FinalAnswerResult)
+        assert result.answer == {"answer": "my answer", "score": 42}
+
+
+def test_final_var_wrong_arg_count():
+    """Test FINAL_VAR with wrong number of args gives clear error."""
+
+    output_fields = [
+        {"name": "answer", "type": "str"},
+        {"name": "score", "type": "int"},
+    ]
+
+    with PythonInterpreter(output_fields=output_fields) as sandbox:
+        with pytest.raises(CodeInterpreterError) as exc_info:
+            sandbox.execute('x = 1; FINAL_VAR("x")')  # Only 1 arg, expects 2
+        assert "expects 2 variable names" in str(exc_info.value)
+
+
+def test_extract_parameters():
+    """Test that _extract_parameters correctly extracts function signatures."""
+    def example_fn(required: str, optional: int = 5, untyped=None) -> str:
+        pass
+
+    sandbox = PythonInterpreter()
+    params = sandbox._extract_parameters(example_fn)
+
+    assert len(params) == 3
+    assert params[0] == {"name": "required", "type": "str"}
+    assert params[1] == {"name": "optional", "type": "int", "default": 5}
+    assert params[2] == {"name": "untyped", "default": None}
+
+
+def test_extract_parameters_complex_types():
+    """Test that _extract_parameters handles complex types gracefully."""
+    def complex_fn(items: list | None = None, data: dict[str, int] | None = None) -> list:
+        pass
+
+    sandbox = PythonInterpreter()
+    params = sandbox._extract_parameters(complex_fn)
+
+    assert len(params) == 2
+    # Complex types like Union are not included in type annotation
+    assert params[0] == {"name": "items", "default": None}
+    assert params[1] == {"name": "data", "default": None}
+
EOF_114329324912

# Show what tests will be collected (for debugging)
echo "Collecting tests..."
pytest --collect-only tests/predict/test_program_of_thought.py tests/primitives/test_python_interpreter.py

# Run target test files with pytest
# Using -xvs flags for better output and single-process mode for safety
# -x: stop on first failure
# -v: verbose output
# -s: no output capture (show print statements)
# --tb=short: shorter traceback format
# -rs: show reasons for skipped tests
pytest -xvs --tb=short -rs tests/predict/test_program_of_thought.py tests/primitives/test_python_interpreter.py

# Capture exit code
rc=$?

# Required: echo test status for judge to parse
echo "OMNIGRIL_EXIT_CODE=$rc"

# Restore original test files
git checkout c21f77bc5a3b5a78e2edd55aa28bb5fdf0aad2c8 "tests/predict/test_program_of_thought.py" "tests/primitives/test_python_interpreter.py"

# Exit with the test result code
exit $rc