import io
import os
import json
import os.path as osp
import decimal
import argparse
import math
import sys
from bisect import bisect_left
from PIL import Image
import numpy as np
import quaternion
from scipy import interpolate
import cv2
from tqdm import tqdm
from multiprocessing import Pool

sys.path.insert(0, osp.dirname(osp.abspath(__file__)))
sys.path.insert(0, osp.join(osp.dirname(osp.abspath(__file__)), "..", "src"))
from streamvggt.datasets.utils.zipio import (  # noqa: E402
    SceneZipWriter,
    asset_root,
    listdir as zlistdir,
    read_bytes,
)
from preprocess_arkitscenes import frame_timestamp  # noqa: E402

# How far a laser-GT depth frame may sit from the RGB frame it is paired with,
# as a fraction of the RGB frame period (0.6 -> 20 ms at 30 fps). Scales with
# the capture rate, admits this release's uniform ~16 ms depth/RGB offset, and
# still rejects anything that is not the nearest frame. Protocol parameter: it
# decides which frames exist and how far depth may sit from its image.
MATCH_WINDOW_FRAMES = 0.6


def get_parser():
    parser = argparse.ArgumentParser()
    parser.add_argument(
        "--arkitscenes_dir",
        default="",
    )
    parser.add_argument(
        "--output_dir",
        default="data/dust3r_data/processed_arkitscenes_highres",
    )
    return parser


def value_to_decimal(value, decimal_places):
    decimal.getcontext().rounding = decimal.ROUND_HALF_UP  # define rounding method
    return decimal.Decimal(str(float(value))).quantize(
        decimal.Decimal("1e-{}".format(decimal_places))
    )


def closest(value, sorted_list):
    index = bisect_left(sorted_list, value)
    if index == 0:
        return sorted_list[0]
    elif index == len(sorted_list):
        return sorted_list[-1]
    else:
        value_before = sorted_list[index - 1]
        value_after = sorted_list[index]
        if value_after - value < value - value_before:
            return value_after
        else:
            return value_before


def get_up_vectors(pose_device_to_world):
    return np.matmul(pose_device_to_world, np.array([[0.0], [-1.0], [0.0], [0.0]]))


def get_right_vectors(pose_device_to_world):
    return np.matmul(pose_device_to_world, np.array([[1.0], [0.0], [0.0], [0.0]]))


def read_traj(traj_path):
    quaternions = []
    poses = []
    timestamps = []
    poses_p_to_w = []
    with open(traj_path) as f:
        traj_lines = f.readlines()
        for line in traj_lines:
            tokens = line.split()
            assert len(tokens) == 7
            traj_timestamp = float(tokens[0])

            timestamps_decimal_value = value_to_decimal(traj_timestamp, 3)
            timestamps.append(
                float(timestamps_decimal_value)
            )  # for spline interpolation

            angle_axis = [float(tokens[1]), float(tokens[2]), float(tokens[3])]
            r_w_to_p, _ = cv2.Rodrigues(np.asarray(angle_axis))
            t_w_to_p = np.asarray(
                [float(tokens[4]), float(tokens[5]), float(tokens[6])]
            )

            pose_w_to_p = np.eye(4)
            pose_w_to_p[:3, :3] = r_w_to_p
            pose_w_to_p[:3, 3] = t_w_to_p

            pose_p_to_w = np.linalg.inv(pose_w_to_p)

            r_p_to_w_as_quat = quaternion.from_rotation_matrix(pose_p_to_w[:3, :3])
            t_p_to_w = pose_p_to_w[:3, 3]
            poses_p_to_w.append(pose_p_to_w)
            poses.append(t_p_to_w)
            quaternions.append(r_p_to_w_as_quat)
    return timestamps, poses, quaternions, poses_p_to_w


def main(rootdir, outdir):
    os.makedirs(outdir, exist_ok=True)
    subdirs = ["Validation", "Training"]
    for subdir in subdirs:
        outsubdir = osp.join(outdir, subdir)
        os.makedirs(outsubdir, exist_ok=True)
        scene_dirs = sorted(
            [
                d
                for d in os.listdir(osp.join(rootdir, subdir))
                if osp.isdir(osp.join(rootdir, subdir, d))
            ]
        )

        with Pool() as pool:
            results = list(
                tqdm(
                    pool.imap(
                        process_scene,
                        [
                            (rootdir, outdir, subdir, scene_subdir)
                            for scene_subdir in scene_dirs
                        ],
                    ),
                    total=len(scene_dirs),
                )
            )

        # Filter None results and other post-processing
        valid_scenes = [result for result in results if result is not None]
        outlistfile = osp.join(outsubdir, "scene_list.json")
        with open(outlistfile, "w") as f:
            json.dump(valid_scenes, f)


def process_scene(args):
    rootdir, outdir, subdir, scene_subdir = args
    # Unpack paths
    scene_dir = osp.join(rootdir, subdir, scene_subdir)
    outsubdir = osp.join(outdir, subdir)
    out_scene_subdir = osp.join(outsubdir, scene_subdir)

    # Validation if necessary resources exist. asset_root resolves each raw
    # asset for both layouts: an extracted <asset>/ directory, or the
    # downloaded <asset>.zip left unextracted (inode-safe layout).
    depth_dir = asset_root(scene_dir, "highres_depth")
    rgb_dir = asset_root(scene_dir, "vga_wide")
    intrinsics_dir = asset_root(scene_dir, "vga_wide_intrinsics")
    traj_path = osp.join(scene_dir, "lowres_wide.traj")
    if (
        depth_dir is None
        or rgb_dir is None
        or intrinsics_dir is None
        or not osp.isfile(traj_path)
    ):
        return None

    depth_files = sorted(zlistdir(depth_dir))
    img_files = sorted(zlistdir(rgb_dir))

    out_scene_subdir = osp.join(outsubdir, scene_subdir)

    # STEP 3: parse the scene and export the list of valid (K, pose, rgb, depth) and convert images
    scene_metadata_path = osp.join(out_scene_subdir, "scene_metadata.npz")
    if osp.isfile(scene_metadata_path):
        print(f"Skipping {scene_subdir}")
    else:
        print(f"parsing {scene_subdir}")
        # loads traj
        timestamps, poses, quaternions, poses_cam_to_world = read_traj(traj_path)

        poses = np.array(poses)
        quaternions = np.array(quaternions, dtype=np.quaternion)
        quaternions = quaternion.unflip_rotors(quaternions)
        timestamps = np.array(timestamps)

        all_depths = sorted(
            [
                (basename, basename.split(".png")[0].split("_")[1])
                for basename in depth_files
            ],
            key=lambda x: float(x[1]),
        )

        # Pair each laser-GT depth frame with the RGB frame nearest in time.
        #
        # This replaces a +/-1 ms name probe inherited from CUT3R, which built
        # its candidate names without :.3f ("427.29499999999996") and so only
        # ever matched an exact name. Depth and RGB timestamps in this release
        # are either identical or uniformly ~16 ms apart -- one frame at 60 Hz,
        # a capture-pipeline offset rather than jitter -- so whole scenes
        # matched nothing: 809 of 2,233 eligible scenes produced output on the
        # 2026-09-09 run, selected by device timing rather than by content.
        #
        # The window is a fraction of the RGB frame period so it scales with
        # the capture rate: at 30 fps it admits the ~16 ms offset while still
        # rejecting a frame that is not the nearest one. It is a protocol
        # parameter -- it decides which frames exist and how far the depth can
        # sit from its image -- so it is named, and the offsets actually used
        # are reported per scene.
        rgb_by_timestamp = {
            frame_timestamp(name): name for name in img_files if name.endswith(".png")
        }
        rgb_timestamps = np.array(sorted(rgb_by_timestamp))
        if rgb_timestamps.size < 2:
            print(f"Skipping {scene_subdir}: {rgb_timestamps.size} RGB frames")
            return None
        match_window = MATCH_WINDOW_FRAMES * float(np.median(np.diff(rgb_timestamps)))

        selected_depths = []
        timestamps_selected = []
        offsets = []
        unmatched = 0
        timestamp_min = timestamps.min()
        timestamp_max = timestamps.max()
        for basename, frame_id in all_depths:
            frame_id = float(frame_id)
            if frame_id < timestamp_min or frame_id > timestamp_max:
                continue
            nearest = rgb_timestamps[np.abs(rgb_timestamps - frame_id).argmin()]
            offset = abs(nearest - frame_id)
            if offset > match_window:
                unmatched += 1
                continue
            offsets.append(offset)
            # the pose is interpolated at the RGB timestamp, since that is the
            # frame the depth is being attached to
            selected_depths.append((basename, frame_id, rgb_by_timestamp[nearest]))
            timestamps_selected.append(float(nearest))
        if offsets:
            print(
                f"{scene_subdir}: matched {len(offsets)} depth frames "
                f"(median offset {np.median(offsets) * 1e3:.1f} ms, "
                f"max {max(offsets) * 1e3:.1f} ms), {unmatched} beyond "
                f"{match_window * 1e3:.1f} ms"
            )

        sky_direction_scene, trajectories, intrinsics, images, depths = (
            convert_scene_metadata(
                scene_subdir,
                intrinsics_dir,
                timestamps,
                quaternions,
                poses,
                poses_cam_to_world,
                img_files,
                selected_depths,
                timestamps_selected,
            )
        )

        if len(images) == 0:
            print(f"Skipping {scene_subdir}")
            return None

        os.makedirs(out_scene_subdir, exist_ok=True)
        assert isinstance(sky_direction_scene, str)

        # all converted frames go into ONE uncompressed zip per scene
        # (inode-safe layout); the write is atomic (.tmp -> rename), and the
        # npz below is saved only after the zip completes, so the existing
        # skip-on-npz check implies a complete frames.zip
        img_set = set(img_files)
        depth_set = set(depth_files)
        with SceneZipWriter(osp.join(out_scene_subdir, "frames.zip")) as writer:
            for image_path, depth_path in zip(images, depths):
                if image_path not in img_set or depth_path not in depth_set:
                    continue

                img = Image.open(io.BytesIO(read_bytes(osp.join(rgb_dir, image_path))))
                depth = cv2.imdecode(
                    np.frombuffer(
                        read_bytes(osp.join(depth_dir, depth_path)), np.uint8
                    ),
                    cv2.IMREAD_UNCHANGED,
                )

                # rotate the image
                if sky_direction_scene == "RIGHT":
                    try:
                        img = img.transpose(Image.Transpose.ROTATE_90)
                    except Exception:
                        img = img.transpose(Image.ROTATE_90)
                    depth = cv2.rotate(depth, cv2.ROTATE_90_COUNTERCLOCKWISE)

                elif sky_direction_scene == "LEFT":
                    try:
                        img = img.transpose(Image.Transpose.ROTATE_270)
                    except Exception:
                        img = img.transpose(Image.ROTATE_270)
                    depth = cv2.rotate(depth, cv2.ROTATE_90_CLOCKWISE)

                elif sky_direction_scene == "DOWN":
                    try:
                        img = img.transpose(Image.Transpose.ROTATE_180)
                    except Exception:
                        img = img.transpose(Image.ROTATE_180)
                    depth = cv2.rotate(depth, cv2.ROTATE_180)

                W, H = img.size
                buf = io.BytesIO()
                img.save(buf, format="JPEG")
                writer.writestr(
                    "vga_wide/" + image_path.replace(".png", ".jpg"), buf.getvalue()
                )

                depth = cv2.resize(depth, (W, H), interpolation=cv2.INTER_NEAREST)
                ok, enc = cv2.imencode(".png", depth)
                assert ok, f"png encode failed for {depth_path}"
                # named for the RGB frame, not the depth frame: the two differ
                # by up to the match window, and the loader reads one basename
                # per frame from the metadata
                writer.writestr("highres_depth/" + image_path, enc.tobytes())

        # save at the end
        np.savez(
            scene_metadata_path,
            trajectories=trajectories,
            intrinsics=intrinsics,
            images=images,
        )
    return scene_subdir


def convert_scene_metadata(
    scene_subdir,
    intrinsics_dir,
    timestamps,
    quaternions,
    poses,
    poses_cam_to_world,
    all_images,
    selected_depths,
    timestamps_selected,
):
    # find scene orientation
    sky_direction_scene, rotated_to_cam = find_scene_orientation(poses_cam_to_world)

    # find/compute pose for selected timestamps
    # most images have a valid timestamp / exact pose associated
    timestamps_selected = np.array(timestamps_selected)
    spline = interpolate.interp1d(timestamps, poses, kind="linear", axis=0)
    interpolated_rotations = quaternion.squad(
        quaternions, timestamps, timestamps_selected
    )
    interpolated_positions = spline(timestamps_selected)

    trajectories = []
    intrinsics = []
    images = []
    depths = []
    # membership in the listing replaces per-probe existence checks: same
    # semantics in both layouts, and O(1) per probe instead of a stat / a
    # namelist scan
    intrinsic_names = set(zlistdir(intrinsics_dir))
    for i, (basename, frame_id, image_path) in enumerate(selected_depths):
        # the pose and the intrinsics belong to the RGB frame, so both are
        # looked up by ITS timestamp, not the depth frame's
        rgb_frame_id = image_path[len(scene_subdir) + 1 : -len(".png")]
        intrinsic_name = f"{scene_subdir}_{rgb_frame_id}.pincam"
        if intrinsic_name not in intrinsic_names:
            print(f"Skipping {intrinsic_name}")
            continue
        intrinsic_fn = osp.join(intrinsics_dir, intrinsic_name)

        w, h, fx, fy, hw, hh = np.loadtxt(
            io.BytesIO(read_bytes(intrinsic_fn))
        )  # PINHOLE

        pose = np.eye(4)
        pose[:3, :3] = quaternion.as_rotation_matrix(interpolated_rotations[i])
        pose[:3, 3] = interpolated_positions[i]

        # the frame is named for its RGB timestamp; both zip members use that
        # name, so the loader keeps reading one basename per frame
        images.append(image_path)
        depths.append(basename)
        if sky_direction_scene == "RIGHT" or sky_direction_scene == "LEFT":
            intrinsics.append([h, w, fy, fx, hh, hw])  # swapped intrinsics
        else:
            intrinsics.append([w, h, fx, fy, hw, hh])
        trajectories.append(
            pose @ rotated_to_cam
        )  # pose_cam_to_world @ rotated_to_cam = rotated(cam) to world

    return sky_direction_scene, trajectories, intrinsics, images, depths


def find_scene_orientation(poses_cam_to_world):
    if len(poses_cam_to_world) > 0:
        up_vector = sum(get_up_vectors(p) for p in poses_cam_to_world) / len(
            poses_cam_to_world
        )
        right_vector = sum(get_right_vectors(p) for p in poses_cam_to_world) / len(
            poses_cam_to_world
        )
        up_world = np.array([[0.0], [0.0], [1.0], [0.0]])
    else:
        up_vector = np.array([[0.0], [-1.0], [0.0], [0.0]])
        right_vector = np.array([[1.0], [0.0], [0.0], [0.0]])
        up_world = np.array([[0.0], [0.0], [1.0], [0.0]])

    # value between 0, 180
    device_up_to_world_up_angle = (
        np.arccos(np.clip(np.dot(np.transpose(up_world), up_vector), -1.0, 1.0)).item()
        * 180.0
        / np.pi
    )
    device_right_to_world_up_angle = (
        np.arccos(
            np.clip(np.dot(np.transpose(up_world), right_vector), -1.0, 1.0)
        ).item()
        * 180.0
        / np.pi
    )

    up_closest_to_90 = abs(device_up_to_world_up_angle - 90.0) < abs(
        device_right_to_world_up_angle - 90.0
    )
    if up_closest_to_90:
        assert abs(device_up_to_world_up_angle - 90.0) < 45.0
        # LEFT
        if device_right_to_world_up_angle > 90.0:
            sky_direction_scene = "LEFT"
            cam_to_rotated_q = quaternion.from_rotation_vector(
                [0.0, 0.0, math.pi / 2.0]
            )
        else:
            # note that in metadata.csv RIGHT does not exist, but again it's not accurate...
            # well, turns out there are scenes oriented like this
            # for example Training/41124801
            sky_direction_scene = "RIGHT"
            cam_to_rotated_q = quaternion.from_rotation_vector(
                [0.0, 0.0, -math.pi / 2.0]
            )
    else:
        # right is close to 90
        assert abs(device_right_to_world_up_angle - 90.0) < 45.0
        if device_up_to_world_up_angle > 90.0:
            sky_direction_scene = "DOWN"
            cam_to_rotated_q = quaternion.from_rotation_vector([0.0, 0.0, math.pi])
        else:
            sky_direction_scene = "UP"
            cam_to_rotated_q = quaternion.quaternion(1, 0, 0, 0)
    cam_to_rotated = np.eye(4)
    cam_to_rotated[:3, :3] = quaternion.as_rotation_matrix(cam_to_rotated_q)
    rotated_to_cam = np.linalg.inv(cam_to_rotated)
    return sky_direction_scene, rotated_to_cam


if __name__ == "__main__":
    parser = get_parser()
    args = parser.parse_args()
    main(args.arkitscenes_dir, args.output_dir)
