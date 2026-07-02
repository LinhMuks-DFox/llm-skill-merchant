<!-- runbook-contract: eval v1 -->
# Evaluation Runbook

<!-- Fill every section. The eval skill navigates by the exact H2 headings
     below — do not rename them. -->

## Overview

<!-- Metric families and what each measures. -->

## Environments

<!-- Which environment/container/service each family needs; how to check
     it is up; how to start it. -->

## Running evaluation

<!-- Orchestrator command(s), flags, defaults. Execution-order dependencies
     (e.g. dump stage gates X). COST GUARDS: which steps are heavy, what is
     skipped by default, which flags override. -->

## Metrics layout

<!-- Where results land: paths, file naming, rough schema. EVERY location
     exception. Caveats about derived artifacts (e.g. normalized audio unfit
     for energy metrics). -->

## Comparison

<!-- Cross-run comparison tool; hazard conditions that invalidate a
     comparison and how to check them. -->

## Reporting rules

<!-- Binding: which split may be reported, default checkpoint, mandatory
     caveats. -->

## Safety rules

<!-- Project-specific red lines, additive to the skill's built-in ones. -->
