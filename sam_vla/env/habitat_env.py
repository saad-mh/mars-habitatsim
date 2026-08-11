from __future__ import annotations

import random
from pathlib import Path
from typing import List, Optional, Sequence

import habitat_sim
import numpy as np
import quaternion
from habitat_sim.agent import AgentConfiguration

from sam_vla.core.goal_geometry import GoalPosition, terrain_patch_mesh
from sam_vla.core.lifecycle import ServiceRegistry
from sam_vla.core.types import Observation, Pose
from sam_vla.env.annotation_meshes import load_mesh_id_map, register_annotation_meshes
from sam_vla.env.terrain import SIZE_X, SIZE_Y, SIZE_Z, HeightmapGrid, Terrain
from sam_vla.env.sim_utils import (
    make_sensor,
    register_semantic_mesh,
    rgb_depth,
    save_obj,
    set_agent_pose,
    set_objects_hidden,
)
from sam_vla.env.rock_generation import RockSpec, load_rock_field, register_rocks

RGB_HEIGHT = 480
RGB_WIDTH = 640
HFOV_DEG = 90.0
DEPTH_MAX_RANGE_M = 10.0

SPAWN_CLEARANCE_M = 1.0
SPAWN_TERRAIN_RADIUS_M = 0.8


class MarsHabitatEnv:
    def __init__(
        self,
        scene_path: str,
        heightmap_path: str,
        services: list = None,
        start_x: float = 0.0,
        start_z: float = 8.0,
        start_yaw: float = 0.0,
        randomise_spawn: bool = False,
        spawn_clearance: float = SPAWN_CLEARANCE_M,
        spawn_terrain_radius: float = SPAWN_TERRAIN_RADIUS_M,
        with_semantic: bool = False,
        rock_field_path: Optional[str] = None,
        annotations_dir: Optional[str] = None,
        annotation_categories: Optional[Sequence[str]] = None,
        flag_seed: Optional[int] = None,
        num_flags: int = 6,
        flag_min_spacing: float = 1.5,
        flag_boundary_margin: float = 2.0,
        flag_spawn_clearance: float = 2.0,
    ):
        self._scene_path = Path(scene_path)
        self._heightmap_path = Path(heightmap_path)
        self._registry = ServiceRegistry()
        for service in services or []:
            self._registry.register(service)
        self._sim = None
        self._agent = None
        self._terrain = None
        self._start_x = start_x
        self._start_z = start_z
        self._start_yaw = start_yaw
        self._randomise_spawn = randomise_spawn
        self._spawn_clearance = spawn_clearance
        self._spawn_terrain_radius = spawn_terrain_radius
        self._with_semantic = with_semantic
        self._rock_field_path = Path(rock_field_path) if rock_field_path else None
        self._annotations_dir = Path(annotations_dir) if annotations_dir else None
        self._annotation_categories = annotation_categories
        # None disables flag placement entirely (default) -- generation is live/seeded
        # rather than a cached manifest (see sam_vla.env.flag_placement), so there's
        # nothing to opt into by path the way rock_field_path works.
        self._flag_seed = flag_seed
        self._num_flags = int(num_flags)
        self._flag_min_spacing = float(flag_min_spacing)
        self._flag_boundary_margin = float(flag_boundary_margin)
        self._flag_spawn_clearance = float(flag_spawn_clearance)
        self.rocks: List[RockSpec] = []
        self.flags: list = []
        self.home_base = None
        self.annotation_mesh_id_map: dict = {}
        self._annotation_objects: dict = {}
        self._annotation_onstage: dict = {}

    def __enter__(self) -> "MarsHabitatEnv":
        sim_cfg = habitat_sim.SimulatorConfiguration()
        sim_cfg.scene_id = str(self._scene_path.expanduser().resolve())
        sim_cfg.enable_physics = False

        rgb_spec = make_sensor(
            "rgb", habitat_sim.SensorType.COLOR, RGB_HEIGHT, RGB_WIDTH, HFOV_DEG
        )
        depth_spec = make_sensor(
            "depth", habitat_sim.SensorType.DEPTH, RGB_HEIGHT, RGB_WIDTH, HFOV_DEG
        )
        # make_sensor doesn't set a far clip; cap depth range here to a sane sensor spec.
        depth_spec.far = DEPTH_MAX_RANGE_M

        sensor_specs = [rgb_spec, depth_spec]
        if self._with_semantic:
            sensor_specs.append(
                make_sensor(
                    "semantic",
                    habitat_sim.SensorType.SEMANTIC,
                    RGB_HEIGHT,
                    RGB_WIDTH,
                    HFOV_DEG,
                )
            )

        agent_cfg = AgentConfiguration()
        agent_cfg.sensor_specifications = sensor_specs

        self._sim = habitat_sim.Simulator(
            habitat_sim.Configuration(sim_cfg, [agent_cfg])
        )
        self._agent = self._sim.initialize_agent(0)

        heightmap_grid = HeightmapGrid(
            self._heightmap_path.expanduser().resolve(),
            size_x=SIZE_X,
            size_z=SIZE_Z,
            size_y=SIZE_Y,
            flip_x=False,
            flip_z=True,
            swap_xz=False,
        )
        self._terrain = Terrain(
            heightmap_grid, flip_x=False, flip_z=False, swap_xz=False
        )

        if self._randomise_spawn:
            x = random.uniform(-SIZE_X / 2.0, SIZE_X / 2.0)
            z = random.uniform(-SIZE_Z / 2.0, SIZE_Z / 2.0)
            yaw = random.uniform(0.0, 2.0 * 3.141592653589793)
        else:
            x, z, yaw = self._start_x, self._start_z, self._start_yaw

        y = self.get_height_at_xz(x, z)
        set_agent_pose(self._agent, x, y, z, yaw)

        from sam_vla.env.home_base import register_home_base

        self.home_base = register_home_base(self._sim, self._terrain, x, z, yaw)

        if self._rock_field_path is not None:
            self.rocks, _rock_config = load_rock_field(self._rock_field_path)
            register_rocks(self._sim, self.rocks)

        if self._flag_seed is not None:
            from sam_vla.env.flag_placement import (
                FlagFieldConfig,
                generate_flag_field,
                register_flags,
            )

            # Always keep flags clear of the rover's own spawn point, on top
            # of any caller-supplied exclude zones.
            flag_config = FlagFieldConfig(
                seed=self._flag_seed,
                num_flags=self._num_flags,
                min_spacing=self._flag_min_spacing,
                boundary_margin=self._flag_boundary_margin,
                exclude_zones=[(x, z, self._flag_spawn_clearance)],
            )
            self.flags = generate_flag_field(flag_config, self._terrain)
            register_flags(self._sim, self.flags)

        if self._annotations_dir is not None:
            self.annotation_mesh_id_map = load_mesh_id_map(self._annotations_dir)
            self._annotation_objects = register_annotation_meshes(
                self._sim, str(self._annotations_dir), self._annotation_categories
            )
            self._annotation_onstage = {
                mesh_id: obj.translation
                for mesh_id, obj in self._annotation_objects.items()
            }
            # Hidden by default (rather than onstage/visible, as
            # register_annotation_meshes leaves them) -- callers outside the
            # run_segmentation_sweep capture path (e.g. nav/rover_controller's
            # live loop, which only ever calls get_observation, never
            # get_full_observation's hide/show dance) must never have these
            # meshes leak into a frame unless they explicitly ask for one via
            # get_mesh_overlay_rgb.
            set_objects_hidden(
                self._annotation_objects, self._annotation_onstage, hidden=True
            )

        self._registry.start_all()
        return self

    def get_height_at_xz(self, x: float, z: float) -> float:
        """Terrain height at (x, z), plus rover clearance, sampled from the heightmap."""
        return (
            self._terrain.local_height_max(x, z, self._spawn_terrain_radius)
            + self._spawn_clearance
        )

    def __exit__(self, exc_type, exc_val, exc_tb):
        self._registry.stop_all()
        if self._sim is not None:
            self._sim.close()
            self._sim = None
        return False

    def get_observation(self, frame_idx: int) -> Observation:
        obs = self._sim.get_sensor_observations()
        rgb, depth = rgb_depth(obs)
        state = self._agent.get_state()
        x, _y, z = (float(v) for v in state.position)
        yaw = float(quaternion.as_rotation_vector(state.rotation)[1])
        pose = Pose(x=x, y=float(state.position[1]), z=z, yaw=yaw)
        return Observation(rgb=rgb, depth=depth, pose=pose, frame_idx=frame_idx)

    def get_mesh_overlay_rgb(self) -> Optional[np.ndarray]:
        """RGB captured with the annotation hull meshes visible in the color
        pass -- i.e. the inverse of get_full_observation's Pass A, and the
        same composited appearance the mesh_tight_bound2-trained LoRA
        segmentation checkpoint (sam_lora_runs/exp10) was trained against.
        For feeding a segmentation model only: never returned by
        get_observation/get_full_observation, so it never reaches the GUI,
        the VLM, or anything else that treats a frame as "what the rover
        sees". Returns None if no annotations_dir was configured. Meshes are
        restored to hidden before returning, matching this env's resting
        state (see __enter__)."""
        if not self._annotation_objects:
            return None
        set_objects_hidden(
            self._annotation_objects, self._annotation_onstage, hidden=False
        )
        obs = self._sim.get_sensor_observations()
        rgb, _depth = rgb_depth(obs)
        set_objects_hidden(
            self._annotation_objects, self._annotation_onstage, hidden=True
        )
        return rgb

    def get_full_observation(self, frame_idx: int) -> Observation:
        """Returns rgb+depth+pose (as get_observation does) AND the semantic
        id buffer (as get_semantic_frame does). `.semantic` is None if
        with_semantic=False (mirrors get_semantic_frame's precondition).

        If annotation meshes are loaded, this does TWO render passes instead
        of one: Pass A (rgb/depth) is captured with the annotation meshes
        moved out of camera view via sim_utils.set_objects_hidden, so they
        can never bake into the training RGB (see next.md -- the mesh sits
        a few cm above terrain for the semantic pass and was, before this
        split, also rendering into RGB as a visible object, producing a
        deterministic occlusion artifact at every positive location that a
        detector could trivially key on instead of real rock appearance).
        Pass B (semantic only) is then captured with the meshes back
        onstage. With no annotation meshes loaded, this is a single render
        call exactly as before -- get_observation() and get_semantic_frame()
        each trigger their own render call, so a caller needing both should
        still prefer this over calling them separately."""
        state = self._agent.get_state()
        x, _y, z = (float(v) for v in state.position)
        yaw = float(quaternion.as_rotation_vector(state.rotation)[1])
        pose = Pose(x=x, y=float(state.position[1]), z=z, yaw=yaw)

        if self._annotation_objects:
            set_objects_hidden(
                self._annotation_objects, self._annotation_onstage, hidden=True
            )
            obs = self._sim.get_sensor_observations()
            rgb, depth = rgb_depth(obs)

            set_objects_hidden(
                self._annotation_objects, self._annotation_onstage, hidden=False
            )
            obs2 = self._sim.get_sensor_observations()
            semantic = np.asarray(obs2["semantic"]) if self._with_semantic else None
        else:
            obs = self._sim.get_sensor_observations()
            rgb, depth = rgb_depth(obs)
            semantic = np.asarray(obs["semantic"]) if self._with_semantic else None

        return Observation(
            rgb=rgb, depth=depth, pose=pose, frame_idx=frame_idx, semantic=semantic
        )

    def verify_annotation_isolation(self, frame_idx: int = -1) -> None:
        """Standing regression check (next.md Step 5): assert
        get_full_observation's actual Pass A RGB (the production path)
        matches an explicit "annotation meshes absent" control render, at
        the current agent pose. This is NOT the same as asserting
        onstage-RGB == hidden-RGB -- those are *expected* to differ
        whenever a mesh is in frame, since a real object was moved out of
        view; that difference is the artifact next.md describes; it's fine.
        What must never happen is get_full_observation itself forgetting to
        hide the meshes before capturing Pass A, i.e. Pass A silently
        matching the "meshes onstage" render instead of the "meshes absent"
        one. Raises AssertionError if that ever happens. No-op if no
        annotation meshes are loaded."""
        if not self._annotation_objects:
            return

        obs = self.get_full_observation(frame_idx)  # production path

        set_objects_hidden(
            self._annotation_objects, self._annotation_onstage, hidden=True
        )
        obs_absent = self._sim.get_sensor_observations()
        rgb_absent, _ = rgb_depth(obs_absent)
        set_objects_hidden(
            self._annotation_objects, self._annotation_onstage, hidden=False
        )  # restore

        if not np.array_equal(obs.rgb, rgb_absent):
            diff_pixels = int(np.any(obs.rgb != rgb_absent, axis=-1).sum())
            raise AssertionError(
                f"annotation mesh isolation broken: get_full_observation's RGB differs by "
                f"{diff_pixels} pixels from a render with annotation meshes explicitly absent -- "
                "the annotation meshes are leaking into the training RGB again (see next.md)."
            )

    def get_semantic_frame(self) -> np.ndarray:
        """Raw per-pixel semantic-id image (H, W) from the semantic sensor:
        each pixel holds the semantic_id of whatever registered mask mesh is
        rendered there (see register_object_mask / goal_geometry.MESH_GOAL_ID
        / MESH_OBST_ID), 0 elsewhere. Requires with_semantic=True."""
        obs = self._sim.get_sensor_observations()
        return np.asarray(obs["semantic"])

    def step(self, pose: Pose) -> None:
        # Match spawn's ground offset (local-max + clearance), not a raw single-point
        # sample, or the agent snaps to bare terrain height every step and clips into
        # the surface.
        y = self.get_height_at_xz(pose.x, pose.z)
        set_agent_pose(self._agent, pose.x, y, pose.z, pose.yaw)

    def register_object_mask(
        self,
        world_pos: GoalPosition,
        semantic_id: int,
        radius: float,
        out_dir: str,
        name: str,
    ):
        """Register a small terrain-following patch mesh at world_pos as a
        render-only, non-collidable object carrying `semantic_id`, so the
        semantic sensor renders a goal/obstacle mask around that point.
        Seeded from an already-backprojected world point
        (goal_geometry.bbox_to_world) rather than a raw pixel + depth patch;
        the patch itself is resampled from the terrain heightmap (self._terrain)
        so it hugs the ground instead of sitting on one flat plane. Requires
        with_semantic=True.
        """
        verts, faces = terrain_patch_mesh(world_pos, radius, self._terrain)
        mesh_dir = Path(out_dir) / "masks"
        mesh_dir.mkdir(parents=True, exist_ok=True)
        mesh_path = str(mesh_dir / f"{name}.obj")
        save_obj(mesh_path, verts, faces)
        return register_semantic_mesh(self._sim, mesh_path, semantic_id)

    def remove_object_mask(self, obj) -> None:
        """Undo a prior register_object_mask outright (not just untag it via
        semantic_id=0) -- callers that repeatedly resolve/rerun within one
        run must actually delete the old mesh, or it keeps sitting in the
        scene as dead render geometry forever."""
        self._sim.get_rigid_object_manager().remove_object_by_id(obj.object_id)


if __name__ == "__main__":
    HERE = Path(__file__).resolve().parent.parent.parent
    scene = HERE / "assets" / "marsyard2022.glb"
    heightmap = HERE / "marsyard2022_terrain_hm_1025.tif"

    with MarsHabitatEnv(str(scene), str(heightmap), services=[]) as env:
        obs = env.get_observation(0)
        print(f"rgb shape={obs.rgb.shape} dtype={obs.rgb.dtype}")
        print(f"pose={obs.pose}")
