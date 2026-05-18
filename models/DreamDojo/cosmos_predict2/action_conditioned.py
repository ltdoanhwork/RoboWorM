# SPDX-FileCopyrightText: Copyright (c) 2025 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# SPDX-License-Identifier: Apache-2.0
#
# Licensed under the Apache License, Version 2.0 (the "License");
# you may not use this file except in compliance with the License.
# You may obtain a copy of the License at
#
# http://www.apache.org/licenses/LICENSE-2.0
#
# Unless required by applicable law or agreed to in writing, software
# distributed under the License is distributed on an "AS IS" BASIS,
# WITHOUT WARRANTIES OR CONDITIONS OF ANY KIND, either express or implied.
# See the License for the specific language governing permissions and
# limitations under the License.

"""
Action-conditioned video generation inference.
"""

import json
import os
from glob import glob
import piq
from pathlib import Path

import mediapy
import numpy as np
import torch
import torch.nn.functional as F
import torchvision

from cosmos_predict2._src.imaginaire.utils import distributed, log
from cosmos_predict2._src.predict2.action.datasets.dataset_utils import euler2rotm, rotm2euler, rotm2quat
from cosmos_predict2._src.predict2.inference.video2world import (
    Video2WorldInference,
)
from cosmos_predict2.cache_runtime import (
    build_cache_runtime_config,
    validate_runtime_backend_args,
)
from cosmos_predict2.action_conditioned_config import (
    ActionConditionedInferenceArguments,
    ActionConditionedSetupArguments,
)
from cosmos_predict2.config import MODEL_CHECKPOINTS, VIDEO_EXTENSIONS

from groot_dreams.dataloader import MultiVideoActionDataset


def _build_svg_experiment_opts(setup_args: ActionConditionedSetupArguments) -> list[str]:
    if not setup_args.use_svg:
        return []

    opts = [
        "model.config.net.self_attention_backend=svg",
        "model.config.net.cross_attention_backend=minimal_a2a",
        f"model.config.net.svg_variant={setup_args.svg_variant}",
    ]
    if setup_args.svg_start_layer_idx is not None:
        opts.append(f"model.config.net.svg_start_layer_idx={setup_args.svg_start_layer_idx}")
    if setup_args.svg_dense_step_frac is not None:
        opts.append(f"model.config.net.svg_dense_step_frac={setup_args.svg_dense_step_frac}")
    if setup_args.svg_sparsity is not None:
        opts.append(f"model.config.net.svg_sparsity={setup_args.svg_sparsity}")
    if setup_args.svg_num_sampled_rows is not None:
        opts.append(f"model.config.net.svg_num_sampled_rows={setup_args.svg_num_sampled_rows}")
    if setup_args.svg_sample_mse_max_row is not None:
        opts.append(f"model.config.net.svg_sample_mse_max_row={setup_args.svg_sample_mse_max_row}")
    if setup_args.svg_num_q_centroids is not None:
        opts.append(f"model.config.net.svg_num_q_centroids={setup_args.svg_num_q_centroids}")
    if setup_args.svg_num_k_centroids is not None:
        opts.append(f"model.config.net.svg_num_k_centroids={setup_args.svg_num_k_centroids}")
    if setup_args.svg_top_p_kmeans is not None:
        opts.append(f"model.config.net.svg_top_p_kmeans={setup_args.svg_top_p_kmeans}")
    if setup_args.svg_min_kc_ratio is not None:
        opts.append(f"model.config.net.svg_min_kc_ratio={setup_args.svg_min_kc_ratio}")
    if setup_args.svg_kmeans_iter_init is not None:
        opts.append(f"model.config.net.svg_kmeans_iter_init={setup_args.svg_kmeans_iter_init}")
    if setup_args.svg_kmeans_iter_step is not None:
        opts.append(f"model.config.net.svg_kmeans_iter_step={setup_args.svg_kmeans_iter_step}")
    return opts


def _build_sito_experiment_opts(setup_args: ActionConditionedSetupArguments) -> list[str]:
    if not setup_args.use_sito:
        return []

    opts = [
        "model.config.net.use_sito=true",
        f"model.config.net.sito_keep_last_n_dense={setup_args.sito_keep_last_n_dense}",
        f"model.config.net.sito_patch_h={setup_args.sito_patch_h}",
        f"model.config.net.sito_patch_w={setup_args.sito_patch_w}",
        f"model.config.net.sito_noise_alpha={setup_args.sito_noise_alpha}",
        f"model.config.net.sito_sim_beta={setup_args.sito_sim_beta}",
    ]
    if setup_args.sito_start_layer_idx is not None:
        opts.append(f"model.config.net.sito_start_layer_idx={setup_args.sito_start_layer_idx}")
    if setup_args.sito_prune_ratio is not None:
        opts.append(f"model.config.net.sito_prune_ratio={setup_args.sito_prune_ratio}")
    return opts


def _build_itm_experiment_opts(setup_args: ActionConditionedSetupArguments) -> list[str]:
    if not setup_args.use_itm:
        return []

    opts = [
        "model.config.net.use_itm=true",
        f"model.config.net.itm_keep_last_n_dense={setup_args.itm_keep_last_n_dense}",
        f"model.config.net.itm_prune_from_step={setup_args.itm_prune_from_step}",
        f"model.config.net.itm_merge_from_step={setup_args.itm_merge_from_step}",
        f"model.config.net.itm_merge_attn={str(setup_args.itm_merge_attn).lower()}",
        f"model.config.net.itm_merge_crossattn={str(setup_args.itm_merge_crossattn).lower()}",
        f"model.config.net.itm_merge_mlp={str(setup_args.itm_merge_mlp).lower()}",
    ]
    if setup_args.itm_start_layer_idx is not None:
        opts.append(f"model.config.net.itm_start_layer_idx={setup_args.itm_start_layer_idx}")
    if setup_args.itm_compress_ratio is not None:
        opts.append(f"model.config.net.itm_compress_ratio={setup_args.itm_compress_ratio}")
    return opts


def _get_robot_states(label, state_key="state", gripper_key="continuous_gripper_state"):
    """
    Extracts the robot arm and gripper states from the label dictionary for the specified frame indices.

    Args:
        label (dict): Dictionary containing robot state information, with keys "state" and "continuous_gripper_state".
        state_key (str): Key for robot state in the dictionary.
        gripper_key (str): Key for gripper state in the dictionary.

    Returns:
        tuple:
            - np.ndarray: Array of arm states for the selected frames, shape (len(frame_ids), state_dim).
            - np.ndarray: Array of gripper states for the selected frames, shape (len(frame_ids),).
    """
    all_states = np.array(label[state_key])
    all_cont_gripper_states = np.array(label[gripper_key])

    return all_states, all_cont_gripper_states


def _get_actions(arm_states, gripper_states, sequence_length, use_quat=False):
    """
    Compute the relative actions between consecutive robot states.

    Args:
        arm_states (np.ndarray): Array of arm states with shape (sequence_length, 6), where each state contains
            [x, y, z, roll, pitch, yaw] or similar.
        gripper_states (np.ndarray): Array of gripper states with shape (sequence_length,).
        sequence_length (int): Number of states in the sequence.
        use_quat (bool): If True, represent rotation as quaternion; otherwise, use Euler angles.

    Returns:
        np.ndarray: Array of actions with shape (sequence_length - 1, 7), where each action contains
            [relative_xyz (3), relative_rotation (3), gripper_state (1)].
    """
    if use_quat:
        action = np.zeros((sequence_length - 1, 8))
    else:
        action = np.zeros((sequence_length - 1, 7))

    for k in range(1, sequence_length):
        prev_xyz = arm_states[k - 1, 0:3]
        prev_rpy = arm_states[k - 1, 3:6]
        prev_rotm = euler2rotm(prev_rpy)
        curr_xyz = arm_states[k, 0:3]
        curr_rpy = arm_states[k, 3:6]
        curr_gripper = gripper_states[k]
        curr_rotm = euler2rotm(curr_rpy)
        rel_xyz = np.dot(prev_rotm.T, curr_xyz - prev_xyz)
        rel_rotm = prev_rotm.T @ curr_rotm

        if use_quat:
            rel_rot = rotm2quat(rel_rotm)
            action[k - 1, 0:3] = rel_xyz
            action[k - 1, 3:7] = rel_rot
            action[k - 1, 7] = curr_gripper
        else:
            rel_rot = rotm2euler(rel_rotm)
            action[k - 1, 0:3] = rel_xyz
            action[k - 1, 3:6] = rel_rot
            action[k - 1, 6] = curr_gripper
    return action  # (l - 1, act_dim)


def get_action_sequence_from_states(
    data,
    fps_downsample_ratio=1,
    use_quat=False,
    state_key="state",
    gripper_scale=1.0,
    gripper_key="continuous_gripper_state",
    action_scaler=20.0,
):
    """
    Get the action sequence from the states.
    """
    arm_states, cont_gripper_states = _get_robot_states(data, state_key, gripper_key)
    actions = _get_actions(
        arm_states[::fps_downsample_ratio],
        cont_gripper_states[::fps_downsample_ratio],
        len(data[state_key][::fps_downsample_ratio]),
        use_quat=use_quat,
    )
    actions *= np.array(
        [action_scaler, action_scaler, action_scaler, action_scaler, action_scaler, action_scaler, gripper_scale]
    )

    return actions


def load_default_action_fn():
    """
    Default action loading function that processes robot states into actions.
    """

    def load_fn(
        json_data: dict,
        video_path: str,
        args: ActionConditionedInferenceArguments,
    ) -> dict:
        """
        Load action data from JSON and prepare it for inference.

        Args:
            json_data: JSON data containing robot states
            video_path: Path to the video file
            args: Inference arguments

        Returns:
            Dictionary containing actions, video data, and metadata
        """
        # Get action sequence from states
        actions = get_action_sequence_from_states(
            json_data,
            fps_downsample_ratio=args.fps_downsample_ratio,
            state_key=args.state_key,
            gripper_scale=args.gripper_scale,
            gripper_key=args.gripper_key,
            action_scaler=args.action_scaler,
            use_quat=args.use_quat,
        )

        # Load video
        video_array = mediapy.read_video(video_path)
        img_array = video_array[args.start_frame_idx]

        # Resize if specified
        if args.resolution != "none":
            try:
                h, w = map(int, args.resolution.split(","))
                img_array = mediapy.resize_image(img_array, (h, w))
            except Exception as e:
                log.warning(f"Failed to resize image to {args.resolution}: {e}")

        return {
            "actions": actions,
            "initial_frame": img_array,
            "video_array": video_array,
            "video_path": video_path,
        }

    return load_fn


def load_callable(name: str):
    """Load a callable function from a module path string."""
    from importlib import import_module

    idx = name.rfind(".")
    assert idx > 0, "expected <module_name>.<identifier>"
    module_name = name[0:idx]
    fn_name = name[idx + 1 :]

    module = import_module(module_name)
    fn = getattr(module, fn_name)
    return fn


def get_video_id(img_path: str):
    """Extract video ID from image path by removing directory and extension."""
    return img_path.split("/")[-1].split(".")[0]


def inference(
    setup_args: ActionConditionedSetupArguments,
    inference_args,
    checkpoint_path,
):
    """Run action-conditioned video generation inference using resolved setup and per-run arguments."""
    torch.enable_grad(False)  # Disable gradient calculations for inference

    # Validate num_latent_conditional_frames at the very beginning
    if inference_args.num_latent_conditional_frames not in [0, 1, 2]:
        raise ValueError(
            f"num_latent_conditional_frames must be 0, 1 or 2, but got {inference_args.num_latent_conditional_frames}"
        )
    validate_runtime_backend_args(setup_args, inference_args)

    # Determine supported extensions based on num_latent_conditional_frames
    if inference_args.num_latent_conditional_frames > 1:
        # Check if input folder contains any videos
        has_videos = False
        for file_name in os.listdir(inference_args.input_root):
            file_ext = os.path.splitext(file_name)[1].lower()
            if file_ext in VIDEO_EXTENSIONS:
                has_videos = True
                break

        if not has_videos:
            raise ValueError(
                f"num_latent_conditional_frames={inference_args.num_latent_conditional_frames} > 1 requires video inputs, "
                f"but no videos found in {inference_args.input_root}. Found extensions: "
                f"{set(os.path.splitext(f)[1].lower() for f in os.listdir(inference_args.input_root) if os.path.splitext(f)[1])}"
            )

        log.info(f"Using video-only mode with {inference_args.num_latent_conditional_frames} conditional frames")
    elif inference_args.num_latent_conditional_frames == 1:
        log.info(f"Using image+video mode with {inference_args.num_latent_conditional_frames} conditional frame")

    # Get checkpoint and experiment from setup args
    checkpoint = MODEL_CHECKPOINTS[setup_args.model_key]
    experiment = setup_args.experiment or checkpoint.experiment
    # pyrefly: ignore  # missing-attribute
    # checkpoint_path = setup_args.checkpoint_path or checkpoint.s3.uri

    # Ensure experiment is not None
    if experiment is None:
        raise ValueError("Experiment name must be provided either in setup args or checkpoint metadata")

    cache_config = build_cache_runtime_config(setup_args)

    # Initialize the inference handler with context parallel support
    video2world_cli = Video2WorldInference(
        experiment_name=experiment,
        ckpt_path=checkpoint_path,
        s3_credential_path="",
        # pyrefly: ignore  # bad-argument-type
        context_parallel_size=setup_args.context_parallel_size,
        config_file=setup_args.config_file,
        experiment_opts=(
            _build_svg_experiment_opts(setup_args)
            + _build_sito_experiment_opts(setup_args)
            + _build_itm_experiment_opts(setup_args)
        ),
        cache_config=cache_config,
    )

    mem_bytes = torch.cuda.memory_allocated(device=torch.device("cuda" if torch.cuda.is_available() else "cpu"))
    log.info(f"GPU memory usage after model load: {mem_bytes / (1024**3):.2f} GB")

    # Only process files on rank 0 if using distributed processing
    rank0 = True
    # pyrefly: ignore  # unsupported-operation
    if setup_args.context_parallel_size > 1:
        rank0 = distributed.get_rank() == 0

    # Ensure save directory exists
    inference_args.save_root = Path(setup_args.save_dir) / checkpoint_path.parent.name
    inference_args.save_root.mkdir(parents=True, exist_ok=True)

    num_frames = setup_args.num_frames
    num_samples = setup_args.num_samples
    dataset = MultiVideoActionDataset(
        num_frames=num_frames,
        dataset_path=setup_args.dataset_path,
        data_split=setup_args.data_split,
        single_base_index=setup_args.single_base_index,
        restrict_len=num_samples,
        deterministic_uniform_sampling=setup_args.deterministic_uniform_sampling,
    )
    batch_inputs = []
    if getattr(setup_args, "batch_input_json", None) is not None:
        log.info(f"Loading batch inputs from JSON file: {setup_args.batch_input_json}")
        with open(setup_args.batch_input_json) as f:
            batch_inputs = json.load(f)

    items_to_run = []
    if batch_inputs:
        for idx, item in enumerate(batch_inputs):
            input_video = item.get("input_video", "")
            output_video = item.get("output_video", f"output_{idx}.mp4")
            
            import re
            match = re.search(r'episode_(\d+)', input_video)
            if not match:
                log.warning(f"Could not parse episode index from {input_video}")
                continue
            traj_id = int(match.group(1))
            
            data_id = None
            current_offset = 0
            for ds in dataset.datasets:
                if hasattr(ds, "lerobot_dataset"):
                    for i, (t_id, base_idx) in enumerate(ds.lerobot_dataset.all_steps):
                        if t_id == traj_id and base_idx == 0:
                            data_id = current_offset + i
                            break
                current_offset += len(ds)
                if data_id is not None:
                    break
            
            if data_id is not None:
                items_to_run.append((data_id, output_video))
            else:
                log.warning(f"Could not find episode {traj_id} in dataset")
    else:
        eval_indices = [
            idx
            for idx in range(len(dataset))
            if not (inference_args.save_root / f"{idx:04d}_metrics.json").exists()
        ]
        items_to_run = [(idx, None) for idx in eval_indices]

    if not items_to_run:
        log.warning(
            "No episodes to run: batch list empty or every index in "
            f"[0, {len(dataset)}) already has *_metrics.json under {inference_args.save_root}. "
            "Use a fresh --save-dir, delete some *_metrics.json files, or raise --num-samples."
        )

    all_psnr = []
    all_ssim = []
    all_lpips = []

    # Process each file in the input directory
    for data_id, custom_output_video in items_to_run:
        data = dataset[data_id]
        gt_video = data["video"].permute(1, 2, 3, 0)
        img_array = data["video"].transpose(0, 1)[:1]
        actions = data["action"][:num_frames - 1].numpy()
        lam_video = data["lam_video"]

        if inference_args.zero_actions:
            actions = np.zeros_like(actions)

        frames = [img_array]
        chunk_video = []
        
        if custom_output_video is None:
            save_name = f"{data_id:04d}"
            video_name = str(inference_args.save_root / save_name)
            chunk_video_name = str(inference_args.save_root / f"{save_name}_pred.mp4")
            gt_video_name = str(inference_args.save_root / f"{save_name}_gt.mp4")
            merged_video_name = str(inference_args.save_root / f"{save_name}_merged.mp4")
            actions_name = str(inference_args.save_root / f"{save_name}_actions.npy")
            metrics_name = inference_args.save_root / f"{save_name}_metrics.json"
        else:
            save_name = Path(custom_output_video).stem
            video_name = custom_output_video
            chunk_video_name = custom_output_video
            Path(custom_output_video).parent.mkdir(parents=True, exist_ok=True)
            gt_video_name = str(Path(custom_output_video).parent / f"{save_name}_gt.mp4")
            merged_video_name = str(Path(custom_output_video).parent / f"{save_name}_merged.mp4")
            actions_name = str(Path(custom_output_video).parent / f"{save_name}_actions.npy")
            metrics_name = Path(custom_output_video).parent / f"{save_name}_metrics.json"

        log.info(f"Saving video to {chunk_video_name}")
        if os.path.exists(chunk_video_name):
            log.info(f"Video already exists: {chunk_video_name}")
            if rank0 and metrics_name.exists():
                try:
                    with open(metrics_name) as f:
                        m = json.load(f)
                    for key in ("psnr", "ssim", "lpips"):
                        if m.get(key) is None:
                            raise ValueError(f"metrics {key} is null in {metrics_name}")
                    all_psnr.append(float(m["psnr"]))
                    all_ssim.append(float(m["ssim"]))
                    all_lpips.append(float(m["lpips"]))
                except (json.JSONDecodeError, KeyError, TypeError, ValueError) as e:
                    log.warning(f"Could not load metrics from {metrics_name}: {e}")
            elif rank0 and not metrics_name.exists():
                log.warning(
                    f"Prediction exists but metrics file missing ({metrics_name}); skipping. "
                    "Delete the prediction video (or the whole episode outputs) to regenerate."
                )
            continue

        first_round = True
        for i in range(inference_args.start_frame_idx, len(actions), inference_args.chunk_size):
            # Handle incomplete chunks
            actions_chunk = actions[i : i + inference_args.chunk_size]
            assert actions_chunk.shape[0] == inference_args.chunk_size
            # if actions_chunk.shape[0] != inference_args.chunk_size:
            #     pad_len = inference_args.chunk_size - actions_chunk.shape[0]
            #     if pad_len > 0:
            #         action_shape = list(actions.shape[1:])
            #         pad_shape = [pad_len] + action_shape
            #         pad_actions = np.zeros(pad_shape, dtype=actions.dtype)
            #         actions_chunk = np.concatenate([actions_chunk, pad_actions], axis=0)

            current_lam_video = lam_video[i * 2 : (i + inference_args.chunk_size) * 2]

            # Convert img_array to tensor and prepare video input
            # pyrefly: ignore  # implicit-import
            if not first_round:
                img_tensor = torchvision.transforms.functional.to_tensor(img_array).unsqueeze(0) * 255.0
            else:
                img_tensor = img_array
            first_round = False
            num_video_frames = actions_chunk.shape[0] + 1
            vid_input = torch.cat(
                [img_tensor, torch.zeros_like(img_tensor).repeat(num_video_frames - 1, 1, 1, 1)], dim=0
            )
            vid_input = vid_input.to(torch.uint8)
            vid_input = vid_input.unsqueeze(0).permute(0, 2, 1, 3, 4)  # (B, C, T, H, W)

            # Call generate_vid2world
            video = video2world_cli.generate_vid2world(
                prompt="",
                input_path=vid_input,
                action=torch.from_numpy(actions_chunk).float()
                if isinstance(actions_chunk, np.ndarray)
                else actions_chunk,
                guidance=inference_args.guidance,
                num_video_frames=num_video_frames,
                num_latent_conditional_frames=inference_args.num_latent_conditional_frames,
                resolution="480,640",
                seed=i,
                negative_prompt=inference_args.negative_prompt,
                lam_video=current_lam_video,
            )
            # Extract next frame and video from result
            video_normalized = (video - (-1)) / (1 - (-1))
            video_clamped = (
                (torch.clamp(video_normalized[0], 0, 1) * 255).to(torch.uint8).permute(1, 2, 3, 0).cpu().numpy()
            )
            next_img_array = video_clamped[-1]  # Last frame is the next frame
            frames.append(next_img_array)
            img_array = next_img_array
            chunk_video.append(video_clamped)

            if inference_args.single_chunk:
                break

        chunk_list = [chunk_video[0]] + [
            chunk_video[i][: inference_args.chunk_size] for i in range(1, len(chunk_video))
        ]
        chunk_video = np.concatenate(chunk_list, axis=0)

        if rank0:
            save_fps = max(1, int(inference_args.save_fps))
            mediapy.write_video(chunk_video_name, chunk_video, fps=save_fps)
            mediapy.write_video(gt_video_name, gt_video.numpy(), fps=save_fps)
            concat_video = np.concatenate([gt_video.numpy(), chunk_video], axis=2)
            mediapy.write_video(merged_video_name, concat_video, fps=save_fps)
            np.save(actions_name, actions)
            log.info(f"Saved video to {chunk_video_name}")
            x_batch = torch.clamp(torch.from_numpy(chunk_video) / 255.0, 0, 1).permute(0, 3, 1, 2)
            y_batch = torch.clamp(gt_video / 255.0, 0, 1).permute(0, 3, 1, 2)
            t_end = min(x_batch.shape[0], y_batch.shape[0])
            h_end = min(x_batch.shape[-2], y_batch.shape[-2])
            w_end = min(x_batch.shape[-1], y_batch.shape[-1])
            if t_end < 1:
                log.warning(
                    f"Skipping metrics for {chunk_video_name}: no overlapping frames "
                    f"(pred T={x_batch.shape[0]}, gt T={y_batch.shape[0]})."
                )
                psnr = ssim = lpips = None
            else:
                x_b = x_batch[:t_end, :, :h_end, :w_end]
                y_b = y_batch[:t_end, :, :h_end, :w_end]
                try:
                    psnr = float(piq.psnr(x_b, y_b).mean().item())
                    ssim = float(piq.ssim(x_b, y_b).mean().item())
                    lpips = float(piq.LPIPS()(x_b, y_b).mean().item())
                except (ZeroDivisionError, ValueError, RuntimeError) as e:
                    log.warning(f"Metrics failed for {chunk_video_name}: {e}")
                    psnr = ssim = lpips = None
            with open(metrics_name, "w") as f:
                json.dump({"psnr": psnr, "ssim": ssim, "lpips": lpips}, f)
            if psnr is not None:
                all_psnr.append(psnr)
                all_ssim.append(ssim)
                all_lpips.append(lpips)

    if rank0:
        if all_psnr:
            mean_psnr = sum(all_psnr) / len(all_psnr)
            mean_ssim = sum(all_ssim) / len(all_ssim)
            mean_lpips = sum(all_lpips) / len(all_lpips)
            print(f"PSNR: {mean_psnr:.3f}")
            print(f"SSIM: {mean_ssim:.3f}")
            print(f"LPIPS: {mean_lpips:.3f}")
            with open(inference_args.save_root / "all_summary.json", "w") as f:
                json.dump(
                    {
                        "psnr": f"{mean_psnr:.3f}",
                        "ssim": f"{mean_ssim:.3f}",
                        "lpips": f"{mean_lpips:.3f}",
                    },
                    f,
                )
        else:
            log.warning(
                "No per-episode metrics collected (empty run or all episodes skipped without *_metrics.json)."
            )
            with open(inference_args.save_root / "all_summary.json", "w") as f:
                json.dump({"psnr": None, "ssim": None, "lpips": None}, f)

    # Synchronize all processes before cleanup
    # pyrefly: ignore  # unsupported-operation
    if setup_args.context_parallel_size > 1:
        torch.distributed.barrier()

    # Clean up distributed resources
    video2world_cli.cleanup()
