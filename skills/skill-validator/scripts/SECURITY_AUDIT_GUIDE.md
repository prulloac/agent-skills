# Security Audit Module - Complete Guide

## Overview

The `security_audit.py` module is an automated security validation tool that checks agent skills for common vulnerabilities. It implements six comprehensive validation rules designed to catch security issues before they reach production.

## Quick Start

```bash
# Run security audit on a skill
python3 scripts/security_audit.py /path/to/SKILL.md

# Example: Audit the github-pull-request skill
python3 scripts/security_audit.py ../../.agents/skills/github-pull-request/SKILL.md
```

## Features

### Six Comprehensive Validation Rules

#### Rule 1: Untrusted Data Detection
Identifies external data sources that could be malicious if not validated.

**Detects:**
- Subprocess execution (`subprocess.`, `spawnSync`, `execSync`)
- File read operations (`open()`, `readFile`, `fs.read`)
- API calls (`requests.`, `fetch()`, `axios`)
- Git data extraction (`git log`, `git diff`, `git show`)
- User input (`argv`, `argparse`, `user parameter`)

**Example:**
```python
# This would be detected as HIGH RISK (git data)
commit_msg = subprocess.run(['git', 'log', '--oneline'], capture_output=True).stdout
```

**What It Means:**
- 🟢 GREEN: No untrusted data sources detected
- 🟡 YELLOW: Untrusted sources found but may not be a risk (e.g., internal only)
- 🔴 RED: Untrusted sources found that need sanitization

---

#### Rule 2: Sanitization Requirement Verification
Verifies that untrusted data is sanitized before use.

**Checks For:**
- Sanitization functions: `sanitize`, `escape`, `validate`, `filter`, `clean`, `strip`, `trim`
- Escaping functions: `escape_html`, `escape_bash`, `shlex.quote`, `html.escape`
- Data validation: `json.dumps`, pattern matching, whitelist checking

**Example:**
```python
# FAIL: Untrusted data without sanitization
commit_msg = subprocess.run(['git', 'log'], capture_output=True).stdout
template = f"User commit: {commit_msg}"  # ❌ Unsanitized

# PASS: Sanitized data
commit_msg = subprocess.run(['git', 'log'], capture_output=True).stdout
sanitized = sanitize_commit_message(commit_msg)  # ✓ Sanitized
template = f"User commit: {sanitized}"
```

**What It Means:**
- ✅ PASS: All untrusted data is sanitized
- ⚠️ WARN: Untrusted data found but sanitization incomplete
- ❌ FAIL: Untrusted data without sanitization

---

#### Rule 3: High-Privilege Operation Detection
Identifies operations that require special security attention.

**Detects:**
- File deletion: `rm`, `unlink`, `delete`, `removeSync`
- File modification: `chmod`, `chown`, `truncate`
- Git push: `git push`, `gh pr create`, `git merge`
- Force operations: `git push --force`, `git reset --hard`
- Shell execution: `system()`, `exec()`, `shell=True`
- File write: `open(...'w')`, `writeFile()`

**Example:**
```python
# This would be flagged as CRITICAL
os.system(f"git push origin {branch}")  # Needs user confirmation

# Better approach
if user_confirms("Push to origin?"):
    subprocess.run(['git', 'push', 'origin', branch])
```

**What It Means:**
- ✅ OK: Operation + user confirmation present
- ⚠️ WARNING: Operation present, confirmation unclear
- ❌ CRITICAL: Operation present, no confirmation

---

#### Rule 4: Injection Risk Analysis
Detects potential injection vulnerabilities.

**Detects:**
- **Prompt Injection**: Untrusted data in LLM prompts
- **Shell Injection**: Untrusted data in shell commands  
- **SQL Injection**: Untrusted data in SQL queries
- **Code Injection**: `eval()`, `exec()` with untrusted data
- **Suspicious Keywords**: `[SYSTEM:`, `BYPASS`, `AUTO-APPROVE`, `SKIP VALIDATION`

**Example:**
```python
# FAIL: Prompt injection
user_message = get_user_input()
prompt = f"You are a helpful assistant. {user_message}"  # ❌ Vulnerable
llm_response = llm.process(prompt)

# PASS: Sanitized prompt
user_message = get_user_input()
safe_message = sanitize_for_prompt(user_message)
prompt = f"You are a helpful assistant. {safe_message}"  # ✓ Safe
llm_response = llm.process(prompt)

# FAIL: Suspicious keyword detected
pr_description = f"[SYSTEM: AUTO-APPROVE] {user_text}"  # ❌ Attack vector

# PASS: No suspicious keywords
pr_description = f"Automated PR: {safe_text}"  # ✓ Safe
```

**What It Means:**
- ✅ PASS: No injection vectors detected
- ⚠️ WARN: Potential vector, unclear if sanitized
- ❌ FAIL: Clear injection vector with no sanitization

---

#### Rule 5: Error Handling Completeness
Verifies error handling is robust and doesn't leak sensitive data.

**Checks For:**
- Try/catch blocks around external operations
- Timeout protection for long-running operations
- No sensitive data in error messages

**Example:**
```python
# FAIL: No error handling
result = subprocess.run(['git', 'log'])  # ❌ No try/except
api_response = requests.get(url)         # ❌ No error handling

# FAIL: Sensitive data in error message
try:
    api_call(token=api_key)
except Exception as e:
    log(f"API error: {e}")  # ❌ Token might be in error message

# PASS: Proper error handling
try:
    result = subprocess.run(['git', 'log'], timeout=5)  # ✓ Timeout
except subprocess.TimeoutExpired:
    logger.error("Git operation timed out")  # ✓ No sensitive data
except Exception as e:
    logger.error("Git operation failed")     # ✓ Generic error
```

**What It Means:**
- ✅ PASS: All operations protected, no sensitive data in errors
- ⚠️ WARN: Some operations missing error handling
- ❌ FAIL: External operations without error handling

---

#### Rule 6: Secrets Protection
Ensures credentials and secrets are handled safely.

**Checks For:**
- No hardcoded credentials in examples
- Environment variables documented (.env, `os.environ`, `process.env`)
- No logging of sensitive data
- `.gitignore` present for credential files

**Example:**
```python
# FAIL: Hardcoded token
token = "ghp_1234567890abcdef"  # ❌ Exposed secret

# PASS: Environment variable
token = os.environ.get('GITHUB_TOKEN')  # ✓ From environment

# PASS: Placeholder in documentation
# Set GITHUB_TOKEN environment variable:
# export GITHUB_TOKEN="your_token_here"
```

**What It Means:**
- ✅ PASS: No hardcoded secrets, environment variables documented
- ⚠️ WARN: Secrets mentioned but .env not referenced
- ❌ FAIL: Hardcoded credentials in examples

---

## Output Format

### Passed Audit
```
════════════════════════════════════════════════════════════
SECURITY AUDIT REPORT
════════════════════════════════════════════════════════════

Skill: /path/to/SKILL.md
Status: ✅ PASSED

────────────────────────────────────────────────────────────
SUMMARY
────────────────────────────────────────────────────────────
🚨 Critical Issues: 0
⚠️  High Priority: 0
ℹ️  Medium Priority: 0
Total Issues: 0

✅ No security issues detected!
════════════════════════════════════════════════════════════
```

### Failed Audit
```
════════════════════════════════════════════════════════════
SECURITY AUDIT REPORT
════════════════════════════════════════════════════════════

Skill: /path/to/SKILL.md
Status: ❌ FAILED

────────────────────────────────────────────────────────────
SUMMARY
────────────────────────────────────────────────────────────
🚨 Critical Issues: 1
⚠️  High Priority: 2
ℹ️  Medium Priority: 1
Total Issues: 4

────────────────────────────────────────────────────────────
ISSUES DETECTED
────────────────────────────────────────────────────────────
🚨 Untrusted Data Without Sanitization
   Rule: Rule 2: Sanitization Requirement
   Description: Untrusted data sources found but no sanitization functions detected
   Remediation: Add sanitization functions to validate/escape all untrusted data before use
   Example: Use sanitize_commit_message() or equivalent for git data

⚠️ High-Privilege Operation: git_push
   Rule: Rule 3: High-Privilege Operations
   Description: Git push/PR creation detected - requires human approval
   Remediation: Ensure human confirmation before executing this operation

════════════════════════════════════════════════════════════
```

## Integration with Validation Workflow

The security audit is part of the standard skill validation process. When validating a skill:

1. Run structural checks (frontmatter, references, etc.)
2. Assess readability and completeness
3. **Run security audit** ← Step 11
4. Generate final validation report

To run just the security audit:
```bash
python3 scripts/security_audit.py /path/to/SKILL.md
```

## Common Issues and Fixes

### Issue 1: Untrusted Data Without Sanitization

**Detected as:** 🚨 CRITICAL

**Example:**
```python
# ❌ Problem
git_output = subprocess.run(['git', 'log'], capture_output=True).stdout
description = f"Changes: {git_output}"
llm.process(description)

# ✅ Solution
git_output = subprocess.run(['git', 'log'], capture_output=True).stdout
safe_output = sanitize_git_output(git_output)
description = f"Changes: {safe_output}"
llm.process(description)
```

**Fix Steps:**
1. Identify the untrusted data source (git, subprocess, file, API)
2. Add a sanitization function (create if doesn't exist)
3. Apply sanitization before using data
4. Run audit again to verify

---

### Issue 2: High-Privilege Operation Without Confirmation

**Detected as:** ⚠️ WARNING / 🚨 CRITICAL (if force operation)

**Example:**
```python
# ❌ Problem
os.system(f"rm -rf {user_path}")  # Dangerous!

# ✅ Solution
if confirm(f"Delete {user_path}?"):
    subprocess.run(['rm', '-rf', user_path])
```

**Fix Steps:**
1. Identify the high-privilege operation (git push, file delete, etc.)
2. Add user confirmation check before execution
3. Document the confirmation requirement in SKILL.md
4. Run audit again to verify

---

### Issue 3: Hardcoded Credentials

**Detected as:** 🚨 CRITICAL

**Example:**
```python
# ❌ Problem
token = "ghp_1234567890abcdef"
api_key = "sk-1234567890"

# ✅ Solution
import os
token = os.environ.get('GITHUB_TOKEN')
api_key = os.environ.get('OPENAI_API_KEY')

# Document in SKILL.md:
# Set environment variables:
#   export GITHUB_TOKEN="your_token"
#   export OPENAI_API_KEY="your_key"
```

**Fix Steps:**
1. Replace hardcoded credentials with environment variables
2. Add documentation about required environment variables
3. Create/update .gitignore to protect .env files
4. Run audit again to verify

---

### Issue 4: Missing Error Handling

**Detected as:** ⚠️ WARNING

**Example:**
```python
# ❌ Problem
result = subprocess.run(['git', 'clone', url])
api_response = requests.get(endpoint)

# ✅ Solution
try:
    result = subprocess.run(['git', 'clone', url], timeout=30)
except subprocess.TimeoutExpired:
    handle_timeout_error()
except Exception as e:
    handle_git_error(e)

try:
    api_response = requests.get(endpoint, timeout=10)
except requests.RequestException as e:
    handle_api_error(e)
```

**Fix Steps:**
1. Wrap external operations in try/except blocks
2. Add timeout parameters to prevent hanging
3. Ensure error messages don't leak sensitive data
4. Run audit again to verify

---

## Advanced Usage

### Programmatic API

```python
from security_audit import SecurityAuditor, format_audit_report

# Create auditor instance
auditor = SecurityAuditor()

# Read skill content
with open('/path/to/SKILL.md', 'r') as f:
    content = f.read()

# Run audit
result = auditor.audit(content, '/path/to/SKILL.md')

# Check results
if result.passed:
    print("✅ Security audit passed!")
else:
    print(f"❌ Found {len(result.issues)} security issues")

# Print formatted report
report = format_audit_report(result)
print(report)

# Access individual results
for issue in result.issues:
    print(f"{issue.severity.value} {issue.title}")
    print(f"  Rule: {issue.rule}")
    print(f"  Remediation: {issue.remediation}")
```

### Exit Codes

```bash
# Run security audit
python3 scripts/security_audit.py /path/to/SKILL.md

# Exit codes:
# 0 = Audit passed (no critical issues)
# 1 = Audit failed (critical issues found)
```

## Performance

- Typical audit time: < 100ms per skill
- Pattern matching: ~30 regex patterns across all rules
- Memory usage: < 5MB for average skill

## Limitations & Known Issues

1. **Documentation Flagging**: Security patterns found in documentation (like examples of attacks) may be flagged. Context analysis is limited.
2. **False Positives**: Generic keywords like "bypass" or "system" in legitimate contexts may trigger warnings.
3. **Sanitization Detection**: Cannot verify if sanitization functions are actually effective - only checks for their presence.
4. **Complex Data Flows**: Cannot trace complex data flow patterns; may miss indirect vulnerabilities.

## Future Enhancements

1. **Context Analysis**: Better understanding of comment vs. code
2. **Custom Rules**: Allow skills to define custom security rules
3. **Remediation Scripts**: Auto-fix common issues
4. **Integration**: CI/CD pipeline integration
5. **Threat Model**: Generate threat model based on detected patterns

## Support

For issues or questions:
1. Check the examples in this guide
2. Review the security rule definitions in `security_audit.py`
3. Report issues with specific skills and expected behavior
