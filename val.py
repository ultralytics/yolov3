# Ultralytics YOLOv3 🚀, AGPL-3.0 license
"""
Validate a trained YOLOv3 detection model on a detection dataset.

Usage:
    $ python val.py --weights yolov5s.pt --data coco128.yaml --img 640

Usage - formats:
    $ python val.py --weights yolov5s.pt                 # PyTorch
                              yolov5s.torchscript        # TorchScript
                              yolov5s.onnx               # ONNX Runtime or OpenCV DNN with --dnn
                              yolov5s_openvino_model     # OpenVINO
                              yolov5s.engine             # TensorRT
                              yolov5s.mlmodel            # CoreML (macOS-only)
                              yolov5s_saved_model        # TensorFlow SavedModel
                              yolov5s.pb                 # TensorFlow GraphDef
                              yolov5s.tflite             # TensorFlow Lite
                              yolov5s_edgetpu.tflite     # TensorFlow Edge TPU
                              yolov5s_paddle_model       # PaddlePaddle
"""

import argparse
import json
import os
import subprocess
import sys
from pathlib import Path

import numpy as np
import torch
from tqdm import tqdm

FILE = Path(__file__).resolve()
ROOT = FILE.parents[0]  # YOLOv3 root directory
if str(ROOT) not in sys.path:
    sys.path.append(str(ROOT))  # add ROOT to PATH
ROOT = Path(os.path.relpath(ROOT, Path.cwd()))  # relative

from models.common import DetectMultiBackend
from utils.callbacks import Callbacks
from utils.dataloaders import create_dataloader
from utils.general import (
    LOGGER,
    TQDM_BAR_FORMAT,
    Profile,
    check_dataset,
    check_img_size,
    check_requirements,
    check_yaml,
    coco80_to_coco91_class,
    colorstr,
    increment_path,
    non_max_suppression,
    print_args,
    scale_boxes,
    xywh2xyxy,
    xyxy2xywh,
)
from utils.metrics import ConfusionMatrix, ap_per_class, box_iou
from utils.plots import output_to_target, plot_images, plot_val_study
from utils.torch_utils import select_device, smart_inference_mode


def save_one_txt(predn, save_conf, shape, file):
    """
    Saves detection results in txt format, including labels and optionally confidence scores.

    Args:
        predn (torch.Tensor): Tensor containing the predicted bounding boxes and class scores in xyxy format.
        save_conf (bool): If True, includes confidence scores in the saved txt file.
        shape (tuple[int, int]): The shape of the original image in the format (height, width).
        file (str | pathlib.Path): Path to the output txt file to save the detection results.

    Returns:
        None

    Note:
        The `predn` tensor should be in the format [x_min, y_min, x_max, y_max, confidence, class] for each detected object.
        The function normalizes bounding box coordinates to the range [0, 1] based on the provided image shape and saves
        them in the format [class, x_center, y_center, width, height, confidence] if `save_conf` is True, otherwise
        [class, x_center, y_center, width, height].

    Example:
        ```python
        import torch

        # Example predicted bounding boxes tensor
        predn = torch.tensor([[50, 30, 200, 150, 0.9, 1], [120, 80, 250, 200, 0.75, 0]])
        save_one_txt(predn, save_conf=True, shape=(800, 600), file='output.txt')
        ```

        This example will save detection results in 'output.txt' with normalized coordinates and confidence scores.
    """
    gn = torch.tensor(shape)[[1, 0, 1, 0]]  # normalization gain whwh
    for *xyxy, conf, cls in predn.tolist():
        xywh = (xyxy2xywh(torch.tensor(xyxy).view(1, 4)) / gn).view(-1).tolist()  # normalized xywh
        line = (cls, *xywh, conf) if save_conf else (cls, *xywh)  # label format
        with open(file, "a") as f:
            f.write(("%g " * len(line)).rstrip() % line + "\n")


def save_one_json(predn, jdict, path, class_map):
    """
    Saves detection results in JSON format containing image_id, category_id, bbox, and score per detection.

    Args:
        predn (torch.Tensor): A tensor containing the predicted bounding boxes and scores in the format [x1, y1, x2, y2, score, class].
        jdict (list): List to which the JSON results will be appended; it is mutable and modified in place.
        path (pathlib.Path): Path object representing the file path of the image; used to extract the image_id.
        class_map (dict[int, int]): A dictionary mapping class indices to their corresponding category_ids, used for COCO dataset compatibility.

    Returns:
        None

    Note:
        The output JSON format is designed to be compatible with COCO dataset annotations, where each detection result consists of an image_id, a category_id, a bounding box, and a confidence score.

    Example:
        ```python
        predn = torch.tensor([[50, 30, 200, 180, 0.9, 1]])
        jdict = []
        path = Path("path/to/image.jpg")
        class_map = {1: 1}
        save_one_json(predn, jdict, path, class_map)
        print(jdict)
        # Output: [{'image_id': 'image', 'category_id': 1, 'bbox': [125.0, 75.0, 150.0, 150.0], 'score': 0.9}]
        ```
    """
    image_id = int(path.stem) if path.stem.isnumeric() else path.stem
    box = xyxy2xywh(predn[:, :4])  # xywh
    box[:, :2] -= box[:, 2:] / 2  # xy center to top-left corner
    for p, b in zip(predn.tolist(), box.tolist()):
        jdict.append(
            {
                "image_id": image_id,
                "category_id": class_map[int(p[5])],
                "bbox": [round(x, 3) for x in b],
                "score": round(p[4], 5),
            }
        )


def process_batch(detections, labels, iouv):
    """
    Return correct prediction matrix for batch detections and ground truth labels over multiple IoU thresholds.

    Args:
        detections (np.ndarray[N, 6]): Array of detection results, each containing [x1, y1, x2, y2, conf, class].
        labels (np.ndarray[M, 5]): Array of ground truth labels, each containing [class, x1, y1, x2, y2].
        iouv (np.ndarray): Array of IoU thresholds for evaluation.

    Returns:
        np.ndarray[N, 10]: Boolean array indicating correct predictions for each of the 10 IoU levels.

    Note:
        The function matches detections with ground truth labels over specified IoU thresholds and checks class identity.
        The results are used for performance evaluation metrics like Precision and Recall.

    Examples:
        ```python
        detections = np.array([[50, 50, 150, 150, 0.9, 0], [30, 30, 120, 120, 0.75, 1]])
        labels = np.array([[0, 50, 50, 150, 150], [1, 30, 30, 120, 120]])
        iouv = np.linspace(0.5, 0.95, 10)
        correct_matrix = process_batch(detections, labels, iouv)
        ```
    """
    correct = np.zeros((detections.shape[0], iouv.shape[0])).astype(bool)
    iou = box_iou(labels[:, 1:], detections[:, :4])
    correct_class = labels[:, 0:1] == detections[:, 5]
    for i in range(len(iouv)):
        x = torch.where((iou >= iouv[i]) & correct_class)  # IoU > threshold and classes match
        if x[0].shape[0]:
            matches = torch.cat((torch.stack(x, 1), iou[x[0], x[1]][:, None]), 1).cpu().numpy()  # [label, detect, iou]
            if x[0].shape[0] > 1:
                matches = matches[matches[:, 2].argsort()[::-1]]
                matches = matches[np.unique(matches[:, 1], return_index=True)[1]]
                # matches = matches[matches[:, 2].argsort()[::-1]]
                matches = matches[np.unique(matches[:, 0], return_index=True)[1]]
            correct[matches[:, 1].astype(int), i] = True
    return torch.tensor(correct, dtype=torch.bool, device=iouv.device)


@smart_inference_mode()
def run(
    data,
    weights=None,  # model.pt path(s)
    batch_size=32,  # batch size
    imgsz=640,  # inference size (pixels)
    conf_thres=0.001,  # confidence threshold
    iou_thres=0.6,  # NMS IoU threshold
    max_det=300,  # maximum detections per image
    task="val",  # train, val, test, speed or study
    device="",  # cuda device, i.e. 0 or 0,1,2,3 or cpu
    workers=8,  # max dataloader workers (per RANK in DDP mode)
    single_cls=False,  # treat as single-class dataset
    augment=False,  # augmented inference
    verbose=False,  # verbose output
    save_txt=False,  # save results to *.txt
    save_hybrid=False,  # save label+prediction hybrid results to *.txt
    save_conf=False,  # save confidences in --save-txt labels
    save_json=False,  # save a COCO-JSON results file
    project=ROOT / "runs/val",  # save to project/name
    name="exp",  # save to project/name
    exist_ok=False,  # existing project/name ok, do not increment
    half=True,  # use FP16 half-precision inference
    dnn=False,  # use OpenCV DNN for ONNX inference
    model=None,
    dataloader=None,
    save_dir=Path(""),
    plots=True,
    callbacks=Callbacks(),
    compute_loss=None,
):
    """
    Validates a trained YOLO model on a dataset and saves detection results in specified formats.

    Args:
        data (str | dict): Path to data configuration file or dictionary with data paths and class information.
        weights (str | list[str], optional): Path(s) to the model weights file(s) (default is None).
        batch_size (int, optional): Batch size for inference (default is 32).
        imgsz (int, optional): Inference image size in pixels (default is 640).
        conf_thres (float, optional): Confidence threshold for detection (default is 0.001).
        iou_thres (float, optional): Intersection over Union (IoU) threshold for Non-Maximum Suppression (NMS) (default is 0.6).
        max_det (int, optional): Maximum number of detections per image (default is 300).
        task (str, optional): Task type - 'train', 'val', 'test', 'speed', or 'study' (default is 'val').
        device (str, optional): Device to run inference on, i.e., GPU ID, 'cpu' (default is "").
        workers (int, optional): Number of DataLoader workers (default is 8).
        single_cls (bool, optional): Treat the dataset as a single-class dataset (default is False).
        augment (bool, optional): Perform augmented inference (default is False).
        verbose (bool, optional): Enable verbose output (default is False).
        save_txt (bool, optional): Save results to text files (default is False).
        save_hybrid (bool, optional): Save hybrid labels + predictions in text files (default is False).
        save_conf (bool, optional): Save confidence scores in text labels if --save_txt is enabled (default is False).
        save_json (bool, optional): Save detection results in COCO JSON format (default is False).
        project (str | Path, optional): Root directory to save results (default is 'runs/val').
        name (str, optional): Sub-directory within the project to save results (default is 'exp').
        exist_ok (bool, optional): Allow existing project/name without incrementing (default is False).
        half (bool, optional): Use FP16 half-precision inference (default is True).
        dnn (bool, optional): Use OpenCV DNN for ONNX inference (default is False).
        model (torch.nn.Module, optional): Pre-instantiated model object (default is None).
        dataloader (torch.utils.data.DataLoader, optional): Pre-instantiated DataLoader object (default is None).
        save_dir (Path, optional): Directory to save results (default is Path("")).
        plots (bool, optional): Generate plots during validation (default is True).
        callbacks (Callbacks, optional): Custom callback function or hooks to run during validation (default is Callbacks()).
        compute_loss (callable, optional): Function to compute the loss if needed (default is None).

    Returns:
        (dict): Dictionary containing validation metrics and other relevant information.
    """
    # Initialize/load model and set device
    training = model is not None
    if training:  # called by train.py
        device, pt, jit, engine = next(model.parameters()).device, True, False, False  # get model device, PyTorch model
        half &= device.type != "cpu"  # half precision only supported on CUDA
        model.half() if half else model.float()
    else:  # called directly
        device = select_device(device, batch_size=batch_size)

        # Directories
        save_dir = increment_path(Path(project) / name, exist_ok=exist_ok)  # increment run
        (save_dir / "labels" if save_txt else save_dir).mkdir(parents=True, exist_ok=True)  # make dir

        # Load model
        model = DetectMultiBackend(weights, device=device, dnn=dnn, data=data, fp16=half)
        stride, pt, jit, engine = model.stride, model.pt, model.jit, model.engine
        imgsz = check_img_size(imgsz, s=stride)  # check image size
        half = model.fp16  # FP16 supported on limited backends with CUDA
        if engine:
            batch_size = model.batch_size
        else:
            device = model.device
            if not (pt or jit):
                batch_size = 1  # export.py models default to batch-size 1
                LOGGER.info(f"Forcing --batch-size 1 square inference (1,3,{imgsz},{imgsz}) for non-PyTorch models")

        # Data
        data = check_dataset(data)  # check

    # Configure
    model.eval()
    cuda = device.type != "cpu"
    is_coco = isinstance(data.get("val"), str) and data["val"].endswith(f"coco{os.sep}val2017.txt")  # COCO dataset
    nc = 1 if single_cls else int(data["nc"])  # number of classes
    iouv = torch.linspace(0.5, 0.95, 10, device=device)  # iou vector for mAP@0.5:0.95
    niou = iouv.numel()

    # Dataloader
    if not training:
        if pt and not single_cls:  # check --weights are trained on --data
            ncm = model.model.nc
            assert ncm == nc, (
                f"{weights} ({ncm} classes) trained on different --data than what you passed ({nc} "
                f"classes). Pass correct combination of --weights and --data that are trained together."
            )
        model.warmup(imgsz=(1 if pt else batch_size, 3, imgsz, imgsz))  # warmup
        pad, rect = (0.0, False) if task == "speed" else (0.5, pt)  # square inference for benchmarks
        task = task if task in ("train", "val", "test") else "val"  # path to train/val/test images
        dataloader = create_dataloader(
            data[task],
            imgsz,
            batch_size,
            stride,
            single_cls,
            pad=pad,
            rect=rect,
            workers=workers,
            prefix=colorstr(f"{task}: "),
        )[0]

    seen = 0
    confusion_matrix = ConfusionMatrix(nc=nc)
    names = model.names if hasattr(model, "names") else model.module.names  # get class names
    if isinstance(names, (list, tuple)):  # old format
        names = dict(enumerate(names))
    class_map = coco80_to_coco91_class() if is_coco else list(range(1000))
    s = ("%22s" + "%11s" * 6) % ("Class", "Images", "Instances", "P", "R", "mAP50", "mAP50-95")
    tp, fp, p, r, f1, mp, mr, map50, ap50, map = 0.0, 0.0, 0.0, 0.0, 0.0, 0.0, 0.0, 0.0, 0.0, 0.0
    dt = Profile(), Profile(), Profile()  # profiling times
    loss = torch.zeros(3, device=device)
    jdict, stats, ap, ap_class = [], [], [], []
    callbacks.run("on_val_start")
    pbar = tqdm(dataloader, desc=s, bar_format=TQDM_BAR_FORMAT)  # progress bar
    for batch_i, (im, targets, paths, shapes) in enumerate(pbar):
        callbacks.run("on_val_batch_start")
        with dt[0]:
            if cuda:
                im = im.to(device, non_blocking=True)
                targets = targets.to(device)
            im = im.half() if half else im.float()  # uint8 to fp16/32
            im /= 255  # 0 - 255 to 0.0 - 1.0
            nb, _, height, width = im.shape  # batch size, channels, height, width

        # Inference
        with dt[1]:
            preds, train_out = model(im) if compute_loss else (model(im, augment=augment), None)

        # Loss
        if compute_loss:
            loss += compute_loss(train_out, targets)[1]  # box, obj, cls

        # NMS
        targets[:, 2:] *= torch.tensor((width, height, width, height), device=device)  # to pixels
        lb = [targets[targets[:, 0] == i, 1:] for i in range(nb)] if save_hybrid else []  # for autolabelling
        with dt[2]:
            preds = non_max_suppression(
                preds, conf_thres, iou_thres, labels=lb, multi_label=True, agnostic=single_cls, max_det=max_det
            )

        # Metrics
        for si, pred in enumerate(preds):
            labels = targets[targets[:, 0] == si, 1:]
            nl, npr = labels.shape[0], pred.shape[0]  # number of labels, predictions
            path, shape = Path(paths[si]), shapes[si][0]
            correct = torch.zeros(npr, niou, dtype=torch.bool, device=device)  # init
            seen += 1

            if npr == 0:
                if nl:
                    stats.append((correct, *torch.zeros((2, 0), device=device), labels[:, 0]))
                    if plots:
                        confusion_matrix.process_batch(detections=None, labels=labels[:, 0])
                continue

            # Predictions
            if single_cls:
                pred[:, 5] = 0
            predn = pred.clone()
            scale_boxes(im[si].shape[1:], predn[:, :4], shape, shapes[si][1])  # native-space pred

            # Evaluate
            if nl:
                tbox = xywh2xyxy(labels[:, 1:5])  # target boxes
                scale_boxes(im[si].shape[1:], tbox, shape, shapes[si][1])  # native-space labels
                labelsn = torch.cat((labels[:, 0:1], tbox), 1)  # native-space labels
                correct = process_batch(predn, labelsn, iouv)
                if plots:
                    confusion_matrix.process_batch(predn, labelsn)
            stats.append((correct, pred[:, 4], pred[:, 5], labels[:, 0]))  # (correct, conf, pcls, tcls)

            # Save/log
            if save_txt:
                save_one_txt(predn, save_conf, shape, file=save_dir / "labels" / f"{path.stem}.txt")
            if save_json:
                save_one_json(predn, jdict, path, class_map)  # append to COCO-JSON dictionary
            callbacks.run("on_val_image_end", pred, predn, path, names, im[si])

        # Plot images
        if plots and batch_i < 3:
            plot_images(im, targets, paths, save_dir / f"val_batch{batch_i}_labels.jpg", names)  # labels
            plot_images(im, output_to_target(preds), paths, save_dir / f"val_batch{batch_i}_pred.jpg", names)  # pred

        callbacks.run("on_val_batch_end", batch_i, im, targets, paths, shapes, preds)

    # Compute metrics
    stats = [torch.cat(x, 0).cpu().numpy() for x in zip(*stats)]  # to numpy
    if len(stats) and stats[0].any():
        tp, fp, p, r, f1, ap, ap_class = ap_per_class(*stats, plot=plots, save_dir=save_dir, names=names)
        ap50, ap = ap[:, 0], ap.mean(1)  # AP@0.5, AP@0.5:0.95
        mp, mr, map50, map = p.mean(), r.mean(), ap50.mean(), ap.mean()
    nt = np.bincount(stats[3].astype(int), minlength=nc)  # number of targets per class

    # Print results
    pf = "%22s" + "%11i" * 2 + "%11.3g" * 4  # print format
    LOGGER.info(pf % ("all", seen, nt.sum(), mp, mr, map50, map))
    if nt.sum() == 0:
        LOGGER.warning(f"WARNING ⚠️ no labels found in {task} set, can not compute metrics without labels")

    # Print results per class
    if (verbose or (nc < 50 and not training)) and nc > 1 and len(stats):
        for i, c in enumerate(ap_class):
            LOGGER.info(pf % (names[c], seen, nt[c], p[i], r[i], ap50[i], ap[i]))

    # Print speeds
    t = tuple(x.t / seen * 1e3 for x in dt)  # speeds per image
    if not training:
        shape = (batch_size, 3, imgsz, imgsz)
        LOGGER.info(f"Speed: %.1fms pre-process, %.1fms inference, %.1fms NMS per image at shape {shape}" % t)

    # Plots
    if plots:
        confusion_matrix.plot(save_dir=save_dir, names=list(names.values()))
        callbacks.run("on_val_end", nt, tp, fp, p, r, f1, ap, ap50, ap_class, confusion_matrix)

    # Save JSON
    if save_json and len(jdict):
        w = Path(weights[0] if isinstance(weights, list) else weights).stem if weights is not None else ""  # weights
        anno_json = str(Path("../datasets/coco/annotations/instances_val2017.json"))  # annotations
        if not os.path.exists(anno_json):
            anno_json = os.path.join(data["path"], "annotations", "instances_val2017.json")
        pred_json = str(save_dir / f"{w}_predictions.json")  # predictions
        LOGGER.info(f"\nEvaluating pycocotools mAP... saving {pred_json}...")
        with open(pred_json, "w") as f:
            json.dump(jdict, f)

        try:  # https://github.com/cocodataset/cocoapi/blob/master/PythonAPI/pycocoEvalDemo.ipynb
            check_requirements("pycocotools>=2.0.6")
            from pycocotools.coco import COCO
            from pycocotools.cocoeval import COCOeval

            anno = COCO(anno_json)  # init annotations api
            pred = anno.loadRes(pred_json)  # init predictions api
            eval = COCOeval(anno, pred, "bbox")
            if is_coco:
                eval.params.imgIds = [int(Path(x).stem) for x in dataloader.dataset.im_files]  # image IDs to evaluate
            eval.evaluate()
            eval.accumulate()
            eval.summarize()
            map, map50 = eval.stats[:2]  # update results (mAP@0.5:0.95, mAP@0.5)
        except Exception as e:
            LOGGER.info(f"pycocotools unable to run: {e}")

    # Return results
    model.float()  # for training
    if not training:
        s = f"\n{len(list(save_dir.glob('labels/*.txt')))} labels saved to {save_dir / 'labels'}" if save_txt else ""
        LOGGER.info(f"Results saved to {colorstr('bold', save_dir)}{s}")
    maps = np.zeros(nc) + map
    for i, c in enumerate(ap_class):
        maps[c] = ap[i]
    return (mp, mr, map50, map, *(loss.cpu() / len(dataloader)).tolist()), maps, t


def parse_opt():
    """
    Parses and returns command-line options for dataset paths, model parameters, and inference settings.

    Args:
      None

    Returns:
      argparse.Namespace: A namespace object containing parsed command-line arguments.

    Args Details:
      data (str): Path to the dataset YAML file. Defaults to 'data/coco128.yaml' in the project root.
      weights (list[str]): Paths to model weight files. Supports multiple paths. Defaults to 'yolov3-tiny.pt' in the project root.
      batch_size (int): Number of samples per batch for inference. Defaults to 32.
      imgsz (int): Inference image size in pixels. Defaults to 640.
      conf_thres (float): Confidence threshold for detecting objects. Defaults to 0.001.
      iou_thres (float): IoU threshold for Non-Maximum Suppression. Defaults to 0.6.
      max_det (int): Maximum number of detections per image. Defaults to 300.
      task (str): Defines the type of task. Options include 'train', 'val', 'test', 'speed', or 'study'. Defaults to 'val'.
      device (str): Specifies the CUDA device, e.g., '0' or '0,1,2,3' or 'cpu'. Defaults to an empty string.
      workers (int): Maximum number of dataloader worker threads (per RANK in DDP mode). Defaults to 8.
      single_cls (bool): If specified, treat the dataset as a single-class dataset. Defaults to False.
      augment (bool): If specified, use augmented inference. Defaults to False.
      verbose (bool): If specified, report mean Average Precision (mAP) per class. Defaults to False.
      save_txt (bool): If specified, save detection results to text files. Defaults to False.
      save_hybrid (bool): If specified, save hybrid results (labels + predictions) to text files. Defaults to False.
      save_conf (bool): If specified, save confidence scores in text label files, applicable if save_txt is True. Defaults to False.
      save_json (bool): If specified, save detection results in COCO-JSON format. Defaults to False.
      project (str): Project directory where results are saved. Defaults to 'runs/val' in the project root.
      name (str): Sub-directory name within the project directory where results are saved. Defaults to 'exp'.
      exist_ok (bool): If specified, do not increment the directory name, even if it exists. Defaults to False.
      half (bool): If specified, use FP16 half-precision for inference. Defaults to False.
      dnn (bool): If specified, use OpenCV DNN for ONNX inference. Defaults to False.

    Examples:
      ```python
      options = parse_opt()
      ```
    """
    parser = argparse.ArgumentParser()
    parser.add_argument("--data", type=str, default=ROOT / "data/coco128.yaml", help="dataset.yaml path")
    parser.add_argument("--weights", nargs="+", type=str, default=ROOT / "yolov3-tiny.pt", help="model path(s)")
    parser.add_argument("--batch-size", type=int, default=32, help="batch size")
    parser.add_argument("--imgsz", "--img", "--img-size", type=int, default=640, help="inference size (pixels)")
    parser.add_argument("--conf-thres", type=float, default=0.001, help="confidence threshold")
    parser.add_argument("--iou-thres", type=float, default=0.6, help="NMS IoU threshold")
    parser.add_argument("--max-det", type=int, default=300, help="maximum detections per image")
    parser.add_argument("--task", default="val", help="train, val, test, speed or study")
    parser.add_argument("--device", default="", help="cuda device, i.e. 0 or 0,1,2,3 or cpu")
    parser.add_argument("--workers", type=int, default=8, help="max dataloader workers (per RANK in DDP mode)")
    parser.add_argument("--single-cls", action="store_true", help="treat as single-class dataset")
    parser.add_argument("--augment", action="store_true", help="augmented inference")
    parser.add_argument("--verbose", action="store_true", help="report mAP by class")
    parser.add_argument("--save-txt", action="store_true", help="save results to *.txt")
    parser.add_argument("--save-hybrid", action="store_true", help="save label+prediction hybrid results to *.txt")
    parser.add_argument("--save-conf", action="store_true", help="save confidences in --save-txt labels")
    parser.add_argument("--save-json", action="store_true", help="save a COCO-JSON results file")
    parser.add_argument("--project", default=ROOT / "runs/val", help="save to project/name")
    parser.add_argument("--name", default="exp", help="save to project/name")
    parser.add_argument("--exist-ok", action="store_true", help="existing project/name ok, do not increment")
    parser.add_argument("--half", action="store_true", help="use FP16 half-precision inference")
    parser.add_argument("--dnn", action="store_true", help="use OpenCV DNN for ONNX inference")
    opt = parser.parse_args()
    opt.data = check_yaml(opt.data)  # check YAML
    opt.save_json |= opt.data.endswith("coco.yaml")
    opt.save_txt |= opt.save_hybrid
    print_args(vars(opt))
    return opt


def main(opt):
    """
    Executes model tasks including training, validation, and benchmarking based on provided command-line options.

    Parameters:
        opt (argparse.Namespace): Parsed command-line arguments including dataset paths, model parameters,
        and inference settings.

    Returns:
        None

    Notes:
        For detailed documentation of the available command-line options, refer to
        the `parse_opt` function or visit the Ultralytics GitHub repository at
        https://github.com/ultralytics/ultralytics.

    Example:
        To validate a model on the COCO dataset with a specified image size and confidence threshold, run the
        following command in the terminal:

        ```python
        python val.py --weights yolov5s.pt --data coco128.yaml --imgsz 640 --conf-thres 0.001
        ```

        For more complex configurations, such as benchmarking speed across various image sizes, you can use:

        ```python
        python val.py --task study --data coco.yaml --iou-thres 0.7 --weights yolov5n.pt yolov5s.pt...
        ```
    """
    check_requirements(ROOT / "requirements.txt", exclude=("tensorboard", "thop"))

    if opt.task in ("train", "val", "test"):  # run normally
        if opt.conf_thres > 0.001:  # https://github.com/ultralytics/yolov5/issues/1466
            LOGGER.info(f"WARNING ⚠️ confidence threshold {opt.conf_thres} > 0.001 produces invalid results")
        if opt.save_hybrid:
            LOGGER.info("WARNING ⚠️ --save-hybrid will return high mAP from hybrid labels, not from predictions alone")
        run(**vars(opt))

    else:
        weights = opt.weights if isinstance(opt.weights, list) else [opt.weights]
        opt.half = torch.cuda.is_available() and opt.device != "cpu"  # FP16 for fastest results
        if opt.task == "speed":  # speed benchmarks
            # python val.py --task speed --data coco.yaml --batch 1 --weights yolov5n.pt yolov5s.pt...
            opt.conf_thres, opt.iou_thres, opt.save_json = 0.25, 0.45, False
            for opt.weights in weights:
                run(**vars(opt), plots=False)

        elif opt.task == "study":  # speed vs mAP benchmarks
            # python val.py --task study --data coco.yaml --iou 0.7 --weights yolov5n.pt yolov5s.pt...
            for opt.weights in weights:
                f = f"study_{Path(opt.data).stem}_{Path(opt.weights).stem}.txt"  # filename to save to
                x, y = list(range(256, 1536 + 128, 128)), []  # x axis (image sizes), y axis
                for opt.imgsz in x:  # img-size
                    LOGGER.info(f"\nRunning {f} --imgsz {opt.imgsz}...")
                    r, _, t = run(**vars(opt), plots=False)
                    y.append(r + t)  # results and times
                np.savetxt(f, y, fmt="%10.4g")  # save
            subprocess.run(["zip", "-r", "study.zip", "study_*.txt"])
            plot_val_study(x=x)  # plot
        else:
            raise NotImplementedError(f'--task {opt.task} not in ("train", "val", "test", "speed", "study")')


if __name__ == "__main__":
    opt = parse_opt()
    main(opt)
