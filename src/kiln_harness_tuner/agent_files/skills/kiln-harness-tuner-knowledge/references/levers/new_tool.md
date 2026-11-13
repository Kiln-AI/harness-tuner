---
title: Code tools
description: Sandboxed Python code tools for the subject task - a new tool, a clone of a code tool with a new description, or a wrapper of any attached tool.
reviewed: 2026-11-13
gateway_ops:
  - list_code_tools
  - get_code_tool
  - get_tool_definition
  - trust_code_tools
  - test_code_tool
  - create_code_tool
  - create_run_config
  - archive_code_tool
---

# Code tools

## What it is

A code tool is a Python function that the subject model can call. Kiln runs
it in a sandbox. It can call other tools through its `tool_allowlist`. The
model sees its `tool_function_name`, its `tool_description` and the
descriptions in its `parameters_schema`.

This lever covers three kinds of change:

- **A new tool**: code with no nested call, or code that calls the
  subject's tools.
- **A clone with a new description**: the code of an existing code tool,
  with a new `tool_description` or new parameter descriptions.
- **A wrapper**: a code tool that calls an attached tool of any kind (a
  code tool, an MCP tool, a built-in tool) and changes what goes in or what
  comes back. An MCP or built-in tool gets a new description only through a
  wrapper.

The subject's own tools are the company's software. The tuner does not
change them. It adds code tools beside them.

## How the tuner changes it

1. Grant trust once in the session: `trust_code_tools`. An untrusted
   create or dry run answers `not_trusted: true` and does nothing.
2. Read the source: `get_code_tool` for a code tool to clone, or
   `get_tool_definition` for the parameters of the tool to wrap.
3. Dry-run the code: `test_code_tool`. Nested calls run for real, so a dry
   run uses reads only, or an id that does not exist.
4. Create the tool: `create_code_tool`. The result gives its id.
5. Create a new run config with `create_run_config`, with
   `kiln_tool::code::<new_id>` in `tools_config.tools`. When the new tool
   replaces a tool, drop the old id on the same run config.

Rules of the object:

- **The functional fields are fixed when the tool is created.** A change
  is a new tool. Never change or archive a tool that another run config
  uses.
- **Each tool has a fresh `tool_function_name`.** A name that a tool that
  is not archived already uses is refused.
- **A subject tool allowlists only subject tools.** Never a tool that can
  reach the Kiln server, never a memory tool, never a skill id, never the
  tool's own id. The code-tool authoring skill gives the rule in full.
- `archive_code_tool` is for a tool that this build created and that no
  run config uses.

## Limits

- The code has at most 64 KB. The parameter names of `run(...)` match
  `parameters_schema`.
- `timeout_seconds` is shared by all nested calls of one call. Nested calls
  go at most 10 deep.
- A nested result can arrive parsed, or as a JSON string. The code parses
  both.
- No value from a train item goes into the code or the description. Code
  searches each build for copies of train content and of eval text.
- The tool's own description is the one text that the model reads at the
  moment it decides to call the tool.
- When the parent's output mode sends the schema as a tool
  (`function_calling`, `function_calling_weak`, or `default` outside Ollama
  and Docker Model Runner), Kiln refuses every call once a tool or a skill
  is attached. Set the mode on the same run config by the fallback of
  [model](model.md), step 4, and list it in `change`. The lever
  [output_mode](output_mode.md) gives the modes.

## See also

- The `kiln-harness-tuner-code-tool-authoring` skill: the contract, the
  allowlist rule, the build discipline and a worked example.
- Its `references/wrappers/README.md`: eight wrapper templates, one for
  each mechanical failure.
- The `kiln-harness-tuner-experiment-build` skill: provenance, the smoke,
  and the text that a tool takes over.
- The `kiln-harness-tuner-gateway` skill: the fields of each operation.
