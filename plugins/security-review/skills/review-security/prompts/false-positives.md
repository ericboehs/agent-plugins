TRUST MODEL - decide where each value comes from before flagging it:

| Attacker-controlled (investigate) | Server-controlled (usually safe) |
|---|---|
| Request params, query strings, form and JSON bodies | Framework settings and app config |
| URL path segments (`/users/:id`) | Environment variables and CLI flags |
| Most request headers, unsigned cookies | Hardcoded constants |
| File uploads (content and filenames) | Internal service URLs from config |
| Webhook and third-party API payloads | Signed or encrypted session data |
| Database content written by other users | Database content written only by admins or the system |
| Message-queue payloads from untrusted producers | Values produced by an allowlist the code controls |

Code paths that require authentication are still in scope; note the required role instead of dismissing the finding.

FALSE POSITIVE FILTERING:

You do not need to run code to reproduce a vulnerability; read the code to determine whether it is real. Never modify files.

HARD EXCLUSIONS - Automatically exclude findings matching these patterns:
1. Denial of Service (DOS) vulnerabilities or resource exhaustion attacks.
2. Secrets or credentials stored on disk if they are otherwise secured.
3. Rate limiting concerns or service overload scenarios.
4. Memory consumption or CPU exhaustion issues.
5. Lack of input validation on non-security-critical fields without proven security impact.
6. Input sanitization concerns for GitHub Action workflows unless they are clearly triggerable via untrusted input.
7. A lack of hardening measures. Code is not expected to implement all security best practices, only flag concrete vulnerabilities.
8. Race conditions or timing attacks that are theoretical rather than practical issues. Only report a race condition if it is concretely problematic.
9. Vulnerabilities related to outdated third-party libraries. These are managed separately. Exception: a dependency-audit scanner hit showing that this diff adds or changes a dependency to a version with a published advisory is in scope.
10. Memory safety issues such as buffer overflows or use-after-free vulnerabilities are impossible in Rust. Do not report memory safety issues in Rust or any other memory safe language.
11. Files that are only unit tests or only used as part of running tests.
12. Log spoofing concerns. Outputting un-sanitized user input to logs is not a vulnerability.
13. SSRF vulnerabilities that only control the path. SSRF is only a concern if it can control the host or protocol.
14. Including user-controlled content in AI system prompts is not a vulnerability.
15. Regex injection. Injecting untrusted content into a regex is not a vulnerability.
16. Regex DOS concerns.
17. Insecure documentation. Do not report any findings in documentation files such as markdown files.
18. A lack of audit logs is not a vulnerability.
19. Pre-existing issues. If the vulnerable code was not added or changed by this diff, and the diff does not newly expose it, exclude it.

PRECEDENTS -
1. Logging high value secrets in plaintext is a vulnerability. Logging URLs is assumed to be safe.
2. UUIDs can be assumed to be unguessable and do not need to be validated.
3. Environment variables and CLI flags are trusted values. Attackers are generally not able to modify them in a secure environment. Any attack that relies on controlling an environment variable is invalid.
4. Resource management issues such as memory or file descriptor leaks are not valid.
5. Subtle or low impact web vulnerabilities such as tabnabbing, XS-Leaks, prototype pollution, and open redirects should not be reported unless they are extremely high confidence.
6. React and Angular are generally secure against XSS. These frameworks do not need to sanitize or escape user input unless it is using dangerouslySetInnerHTML, bypassSecurityTrustHtml, or similar methods. Do not report XSS vulnerabilities in React or Angular components or tsx files unless they are using unsafe methods.
7. Most vulnerabilities in GitHub Action workflows are not exploitable in practice. Before validating a GitHub Action workflow vulnerability ensure it is concrete and has a very specific attack path.
8. A lack of permission checking or authentication in client-side JS/TS code is not a vulnerability. Client-side code is not trusted and does not need to implement these checks, they are handled on the server-side. The same applies to all flows that send untrusted data to the backend, the backend is responsible for validating and sanitizing all inputs.
9. Only include MEDIUM findings if they are obvious and concrete issues.
10. Most vulnerabilities in ipython notebooks (*.ipynb files) are not exploitable in practice. Before validating a notebook vulnerability ensure it is concrete and has a very specific attack path where untrusted input can trigger the vulnerability.
11. Logging non-PII data is not a vulnerability even if the data may be sensitive. Only report logging vulnerabilities if they expose sensitive information such as secrets, passwords, or personally identifiable information (PII).
12. Command injection vulnerabilities in shell scripts are generally not exploitable in practice since shell scripts generally do not run with untrusted user input. Only report command injection vulnerabilities in shell scripts if they are concrete and have a very specific attack path for untrusted input.

SIGNAL QUALITY CRITERIA - For remaining findings, assess:
1. Is there a concrete, exploitable vulnerability with a clear attack path?
2. Does this represent a real security risk vs theoretical best practice?
3. Are there specific code locations and reproduction steps?
4. Would this finding be actionable for a security team?
