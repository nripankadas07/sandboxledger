        # Project Brief

        sandboxledger exists to solve a narrow, inspectable developer-tooling problem:
        Content-addressed run ledger for reproducible agent and benchmark evaluations.

        ## Portfolio Role

        This repository is part of the local-first engineering portfolio around
        agentic AI infrastructure, evaluation, parsing, safety boundaries, and
        small tools that can be understood from a fresh source checkout. It is not
        here to inflate repository count; it should either provide a reusable
        primitive, a benchmark surface, or a concrete local workflow.

        Topics: agent-evaluation, benchmark, developer-tools, llmops, local-first, merkle-tree, python, reproducibility

        ## Current Gates

        - Latest completed CI: success
        - Source files counted by audit: 3
        - Test files counted by audit: 1
        - Latest release: not release-tracked yet
        - License: MIT

        ## Upgrade Path

        - Add a fixture-driven demo that can run without API keys.
- Export artifacts that can be inspected by PatchGym, TraceWeave, or SandboxLedger.
- Document failure modes, limits, and the boundary between deterministic checks and model-judged behavior.

        ## Reviewer Contract

        A serious reviewer should be able to clone the repository, read the
        README and this brief, run the tests, and understand exactly what is
        claimed. Future work should prefer deeper correctness, better fixtures,
        clearer limits, and stronger local demos over broad feature lists.
