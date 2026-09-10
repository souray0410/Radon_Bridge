# Expanded-cohort execution gates (2026-09-10)

The user authorized preparation and automatic GPU submission after readiness. Shared
raw-data audit and native-model workflows are maintained in the private Model_Training
repository (`expanded/PROTOCOL.md`, initial implementation 0c6a63b). Research methods,
accepted data manifests, parents, fitted bases and results remain project-owned.

First CPU-only inventory: 93,127 unique imaged participants; 85,664 with at least one
same-visit CFP/OCT paired eye; 84,215 with bilateral pairs. These are archive metadata
counts before phenotype, image-quality, consent/withdrawal and final eligibility
checks, not accepted disease-cohort counts. Both label exports are audited separately.

GPU submission is gated on accepted data/cache, executable frozen task manifests,
preloaded weights, environment/resource checks and tested checkpoint-safe dispatch.
Allocation must immediately execute actual ready tasks. Project work and its exact native-model prerequisites have priority. When a project
ends, is user-paused/cancelled or fails, its freed GPU group automatically starts an
already validated task from the finite baseline-model queue; the other project is
unaffected. When that project is ready again, checkpoint and exit the baseline, then
return the group to the project. Prepare fallback before allocation, preserve its
independent complete model/recovery artifacts, and never change locked project parents
or repeat accepted baselines. Release only when no ready project or baseline task
remains; no placeholder occupancy or indefinite input waiting.
The periodic assistant monitor is not the mechanism that starts an allocated GPU.

Use new participant-level splits and newly trained native parents. Do not initialize
from old UKB models if they were trained on participants in the new test. Preserve
historical exposure metadata; this is internal validation, not an external cohort.
At least one paired eye is proposed; validate masked-eye aggregation before admitting
single-eye participants. Lock finite development tuning and then parent checkpoints
before main project comparisons. Later background candidates do not change an active
comparison generation. No test performance is accessed during preparation or tuning.

Radon_Bridge: preserve independently pretrained native heads and the branch protocol;
do not restore the cancelled learned terminal fusion study. Refit SVD on the new
training features, with explicit rank/width for ResNet50 channels.

Current cycle is `2026_09_10_11_11_31`. Allocate three A100 80GB GPUs for
at most72h with salloc: one exclusive GPU per project and one for a finite native
models queue. Freed project lanes may backfill from that queue; returning project
work checkpoints/exits only its own fallback. Do not change locked parent models.
Each Slurm step must have explicit GPU, CPU and host-memory resources; allocated
GPU UUIDs must be distinct. Multi-GPU models require separately validated windows.

The independent Model_Training runtime passed the WS02 two-lane finite acceptance
recorded in experiments/2026_09_10_11_11_31: real Radon_Bridge ResNet18 CFP/OCT3D,
native ResNet50, and ResNet34 fallback. Project pause/return and native SIGKILL
recovery matched uninterrupted full states and logits exactly. This is operational
evidence, not a scientific result or a full LOOK/expanded-cohort trainer acceptance.
CPU tests also validate supervisor crash reattachment without duplicate workers.

Remaining launch gates: complete scientific trainer adapters, accepted expanded
cohort/masks/cache, frozen comparison manifests, and actual Slurm three-step isolation
and allocation-owner checks. The GPU application has not been submitted by this
acceptance. No test performance was read and no accepted model store was overwritten.

See [validate before switching](validation_workflow.md) for the host-independent
development process. ws02 is preferred when available, never a mandatory dependency.

Unexpected project termination is also an automatic fallback trigger: observe process
exit, block immediate retry, and dispatch a ready model on the freed lane. A diagnosed
project resumes by a once-only retry command; do not repeatedly restart faulty code.
