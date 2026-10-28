# mujoco_playground_go1_footstand-standard

| | |
|---|---|
| Benchmark | MuJoCo Playground |
| Mode | standard (`eai-standard/2.2`) |
| Twin | `mujoco_playground_go1_footstand-privileged` |
| Simulator / robot | `mujoco` / `unitree-go1` |
| Family / instance | `mujoco_playground/Go1Footstand` / seed 0 |
| Oracle | `full` |
| Agent time budget | 1800 s; tokens: protocol default (docs/protocol/running.md "Official runs") |
| Base image | `ghcr.io/mll-lab-nu/efe:mujoco-0.1.3` |

## Task
MuJoCo Playground `Go1Footstand` (Unitree Go1) on the same frozen instance as `mujoco_playground_go1_footstand-privileged`: Make the Unitree Go1 stand up on its hind legs, nose up, front legs in the air, and balance there for 2 s.
From standing, it has 10 s to get into a footstand on its hind legs and hold it for 2 s (Playground's footstand reward aims at the IMU 0.53 m high). Standard mode (eai-standard/2.2): the agent drives the robot through a client, with 10 resets (only
the last episode is graded), the robot's own sensors and the cameras that follow it.

## Difficulty
Same instance and success check as `mujoco_playground_go1_footstand-privileged`. In standard mode the agent loses free resets, the simulator and
the world state: it sees camera images and proprioception (joints, IMU, foot contacts), acts in joint position chunks,
and gets 10 resets (`RCB_RESET_BUDGET`, the compose file's default; PROTOCOL §2), so it has to close the loop
on the robot's own sensors; only the last episode is graded.

## Reference solution
`solution/oracle_replay.py` streams the privileged reference's rows (`solution/oracle.npy`, 113 rows, float32-exact)
through the client in `hold` chunks; it uses no privileged information at run time. The service's recorded trajectory
is then exactly the privileged reference, and the episode ends with success after 113 control steps.

## Verification
The verdict is the live episode's (`graded_by = "live"`, `replays = 0`): the sim service runs the task's check on the
episode it ran and records every executed control step. The collect hook (`environment/sim/finalize.sh`) ends the
service, writes that verdict into `final.json` (nothing is replayed to grade it), then renders `replay.mp4` from the
recorded trajectory in one video-only pass (`environment/sim/video.py`), which never changes the verdict;
`tests/grade.py` (separate sandbox, no network) passes iff the live check succeeded. The service checks the frozen
instance when it builds the scene: a start state that does not hash to the instance's `state_sha` gets no episode
(`instance_mismatch`, `infra_error = 1`). Oracle: success after 113 control steps.

## Resources
Caps per container (PROTOCOL §6).

| Container | CPUs | Memory | Processes | GPU memory | Disk |
|---|---|---|---|---|---|
| `main` (the agent's) | 2 | 4 GiB | 1024 | no GPU | 10 GiB |
| `sim` | 4 | 4 GiB | 1024 | no GPU | — |
| verifier (as `main`) | 2 | 4 GiB | no cap | no GPU | 10 GiB |

- GPU: not needed.
- Measured: memory: sim 0.7 GB (a per-container memory sampler); CPU only; CPU p90 1.9 cores (a per-container sampler every 30 s)
- Measured (caps): per-container peaks in 31 past trials: the agent's container memory 0.8 GiB, 163 threads, CPU 1.2 cores, disk 0.8 GiB; the sim service memory 0.9 GiB, 116 threads, CPU at its cap (4)

## Details
| | |
|---|---|
| Upstream | MuJoCo Playground @ 4057c14 (Apache-2.0): `locomotion/go1/xmls/scene_mjx_flat_terrain.xml`; MuJoCo Menagerie @ 1b86ece (`unitree_go1`); MuJoCo 3.3.7 on the CPU |
| Service | `environment/sim/server.py` (the adapter) on the shared 2.2 layer `rcb_limited.py` (`embodied_first_exam/standard/`); cameras `track`, `side`, `back`, `top` (they follow the robot) (320 x 240), the feet's kinematics in the trunk frame |
| Resources | 4 CPUs, no GPU (CPU physics, EGL or OSMesa rendering); the collect hook replays nothing, its video pass takes well under a minute (at most the horizon, ~150 frames) |
