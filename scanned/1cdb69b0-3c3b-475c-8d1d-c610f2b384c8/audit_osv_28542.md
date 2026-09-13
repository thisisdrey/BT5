# [C] llama-cpp-python vulnerable to Remote Code Execution by Server-Side Template Injection in Model Metadata

## Summary
Severity: Critical
Advisory: CVE-2024-34359
Aliases: GHSA-56xg-wfcc-g829, PYSEC-2026-392
CVSS: 9.6 (CVSS:3.1/AV:N/AC:L/PR:N/UI:R/S:C/C:H/I:H/A:H)
Published: 2024-05-10
Source: https://osv.dev/vulnerability/CVE-2024-34359
Type: osv

## Details
llama-cpp-python is the Python bindings for llama.cpp. `llama-cpp-python` depends on class `Llama` in `llama.py` to load `.gguf` llama.cpp or Latency Machine Learning Models. The `__init__` constructor built in the `Llama` takes several parameters to configure the loading and running of the model. Other than `NUMA, LoRa settings`, `loading tokenizers,` and `hardware settings`, `__init__` also loads the `chat template` from targeted `.gguf` 's Metadata and furtherly parses it to `llama_chat_format.Jinja2ChatFormatter.to_chat_handler()` to construct the `self.chat_handler` for this model. Nevertheless, `Jinja2ChatFormatter` parse the `chat template` within the Metadate with sandbox-less `jinja2.Environment`, which is furthermore rendered in `__call__` to construct the `prompt` of interaction. This allows `jinja2` Server Side Template Injection which leads to remote code execution by a carefully constructed payload.

## References
- https://github.com/CVEProject/cvelistV5/tree/main/cves/2024/34xxx/CVE-2024-34359.json
- https://github.com/abetlen/llama-cpp-python/security/advisories/GHSA-56xg-wfcc-g829
- https://nvd.nist.gov/vuln/detail/CVE-2024-34359
- https://github.com/abetlen/llama-cpp-python/commit/b454f40a9a1787b2b5659cd2cb00819d983185df
