"""Runs CNN federated learning for MNIST dataset."""

from typing import Dict, Union,Tuple
import mlflow
import flwr as fl
import hydra
from hydra.core.hydra_config import HydraConfig
from hydra.utils import instantiate
from omegaconf import DictConfig, OmegaConf
from flwr.client import Client, ClientApp, NumPyClient
from flwr.common import Metrics, Context
from flwr.server import ServerApp, ServerConfig, ServerAppComponents
from flwr.server.strategy import FedAvg
from flwr.simulation import run_simulation
from fedprox import client, server, utils
from fedprox.client import gen_client_fn , FlowerClient
from fedprox.dataset import load_datasets
from fedprox.utils import LabelDistributionVisualizer,visualize_class_domain_shift,visualize_class_domain_shift_pathmnist
import mlflow
from  mlflow.tracking import MlflowClient
import time
import nest_asyncio
from flwr.common import ConfigsRecord, MetricsRecord, ParametersRecord
import os
import subprocess
#from fedprox.mlflowtracker import setup_tracking
from fedprox.features_visualization import StructuredFeatureVisualizer
from fedprox.strategy import FedAVGWithEval ,MOONStrategy
from fedprox.dataset_preparation import SameModalityDomainShift , BreastMnistDataset ,build_transform
from fedprox.models import get_model ,Model,save_client_model,load_client_model, test_gpaf,init_net,test_moon,load_client_model_moon, test
#from fedprox.models import Generator
FitConfig = Dict[str, Union[bool, float]]
import mlflow
import subprocess
import os
import time
import matplotlib.pyplot as plt
import seaborn as sns
import torch
import numpy as np
from typing import List
from torch.utils.data import DataLoader
strategy="gpaf"
# approach gpaf : global generator with non domain and non contrastive loss
 # Create or get experiment
experiment_name = "gpaf_noniid_pneu"
experiment = mlflow.get_experiment_by_name(experiment_name)
if experiment is None:
        experiment_id = mlflow.create_experiment(experiment_name)
        print(f"Created new experiment with ID: {experiment_id}")
else:
        print(f"Using existing experiment with ID: {experiment.experiment_id}")
backend_config = {"client_resources": {"num_cpus":1 , "num_gpus": 0.0}}
# When running on GPU, assign an entire GPU for each client
DEVICE = torch.device('cuda' if torch.cuda.is_available() else 'cpu')   
# partition dataset and get dataloaders

import torch
import numpy as np
import matplotlib.pyplot as plt
import seaborn as sns
from torch.utils.data import DataLoader
from typing import List

def visualize_intensity_distributions_pathmnist_two_clients(
    train_loaders: List[DataLoader],
    batch_size: int = 64
):
    """
    Visualize pixel intensity distributions for exactly two clients:
      - Client 0 → PathMNIST train split
      - Client 1 → PathMNIST test  split

    Args:
      train_loaders: [loader0, loader1]
      batch_size:    how many samples to batch when streaming stats
    """
    assert len(train_loaders) == 2, "Expect exactly two DataLoaders"

    # 1) Device detect
    device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
    print(f"Visualizing on device: {device}")

    # 2) Plot setup
    clients = ['Client 0 (train)', 'Client 1 (test)']
    colors  = ['blue', 'red']
    fig, (ax1, ax2) = plt.subplots(2, 1, figsize=(12, 10))
    stats = {}

    # 3) Stream each client’s pixels
    for cid, loader in enumerate(train_loaders):
        all_pixels = []
        # Wrap the dataset in a simple DataLoader for batching
        batcher = DataLoader(loader.dataset,
                             batch_size=batch_size,
                             shuffle=False,
                             num_workers=3,
                             pin_memory=torch.cuda.is_available())
        for imgs, _ in batcher:
            imgs = imgs.to(device, non_blocking=True).float()
            flat = imgs.view(imgs.size(0), -1)
            all_pixels.append(flat.cpu().numpy().ravel())
        pixels = np.concatenate(all_pixels)

        # Compute stats
        mean_val   = pixels.mean()
        std_val    = pixels.std()
        median_val = np.median(pixels)
        stats[clients[cid]] = (mean_val, std_val, median_val)

        # KDE plot
        sns.kdeplot(
            data=pixels,
            ax=ax1,
            color=colors[cid],
            label=clients[cid],
            linewidth=2
        )

    # 4) Finalize KDE
    ax1.set_title('Pixel Intensity Distributions')
    ax1.set_xlabel('Pixel Value')
    ax1.set_ylabel('Density')
    ax1.legend()
    ax1.grid(alpha=0.3)

    # 5) Heatmap of stats
    stats_matrix = np.array([
        [stats['Client 0 (train)'][0], stats['Client 1 (test)'][0]],  # means
        [stats['Client 0 (train)'][1], stats['Client 1 (test)'][1]],  # stds
        [stats['Client 0 (train)'][2], stats['Client 1 (test)'][2]]   # medians
    ])
    sns.heatmap(
        stats_matrix,
        ax=ax2,
        xticklabels=clients,
        yticklabels=['Mean', 'Std Dev', 'Median'],
        cmap='YlOrRd',
        annot=True,
        fmt='.4f',
        cbar_kws={'label': 'Value'}
    )
    ax2.set_title('Summary Statistics per Client')

    plt.tight_layout()
    plt.savefig('pathmnist_two_client_intensity.png', dpi=300, bbox_inches='tight')
    plt.show()

def visualize_intensity_distributions(trainloaders: List[DataLoader], num_clients: int):
    plt.figure(figsize=(12, 6))
    colors = ['blue', 'red', 'green', 'purple', 'orange', 'brown', 'pink', 'gray']
    fig, (ax1, ax2) = plt.subplots(2, 1, figsize=(12, 10))
    stats = {}
    print(f'trainloaders {trainloaders}')
    for client_id in range(num_clients):
        try:
            # Get the complete dataset for this client
            client_dataset = trainloaders[client_id].dataset
            print(f'trainloaders 1 {client_dataset}')
            all_images = []
            
            # Collect ALL images for this client
            for idx in range(len(client_dataset)):
                #print(f'image IDX 2344 {idx}')
                image, _ = client_dataset[idx]
                #print(f' image 2344 {image}' )
                all_images.append(image)
            
            # Convert to tensor and flatten
            images_flat = torch.stack(all_images).float().cpu().numpy().flatten()
            
            # Calculate statistics using all data points
            mean_val = np.mean(images_flat)
            std_val = np.std(images_flat)
            median_val = np.median(images_flat)
            
            stats[f'Client {client_id}'] = {
                'mean': mean_val,
                'std': std_val,
                'median': median_val
            }
            
            # Plot distribution using all data points
            sns.kdeplot(
                data=images_flat,
                ax=ax1,
                color=colors[client_id % len(colors)],
                label=f'Client {client_id}',
                linewidth=2
            )
            
        except Exception as e:
            print(f"Error processing client {client_id}: {str(e)}")
            continue
    
    ax1.set_title('Pixel Intensity Distributions Across Clients', fontsize=12)
    ax1.set_xlabel('Pixel Value', fontsize=10)
    ax1.set_ylabel('Density', fontsize=10)
    ax1.legend()
    ax1.grid(True, alpha=0.3)
    
    # Create statistics table
    stats_data = np.array([[
        stats[f'Client {i}']['mean'],
        stats[f'Client {i}']['std'],
        stats[f'Client {i}']['median']
    ] for i in range(num_clients)])
    
    sns.heatmap(
        stats_data.T,
        ax=ax2,
        xticklabels=[f'Client {i}' for i in range(num_clients)],
        yticklabels=['Mean', 'Std Dev', 'Median'],
        cmap='YlOrRd',
        annot=True,
        fmt='.4f',
        cbar_kws={'label': 'Value'}
    )
    ax2.set_title('Statistical Measures of Pixel Distributions', fontsize=12)
    
    plt.tight_layout()
    plt.savefig('intensity_distributions.png', dpi=300, bbox_inches='tight')
    plt.close()

    
def evaluate_metrics_aggregation_fn(eval_metrics: List[Tuple[int, Dict[str, float]]]) -> Dict[str, float]:
        """Aggregate evaluation metrics from multiple clients."""
        # Unpack the evaluation metrics from each client
        losses = []
        accuracies = []
        for _, metrics in eval_metrics:
            losses.append(metrics["loss"])
            accuracies.append(metrics["accuracy"])
        
        # Aggregate the metrics
        return {
            "loss": sum(losses) / len(losses),
            "accuracy": sum(accuracies) / len(accuracies),
        }
def get_on_evaluate_config_fn():
    """Return a function which returns training configurations."""

    def evaluate_config(server_round: int):
        print('server round sanaa'+str(server_round))
        """Return a configuration with static batch size and (local) epochs."""
        config = {
            "server_round": str(server_round),
        }
        return config

    return evaluate_config
def get_server_fn(mlflow=None):
 """Create server function with MLflow tracking."""
 def server_fn(context: Context) -> ServerAppComponents:
    global strategy
    batch_size=32
    num_clients=18
    if strategy=="fedavg":
      
      strategyi = FedAVGWithEval(
      fraction_fit=1.0,  # Train with 50% of available clients
      fraction_evaluate=0.5,  # Evaluate with all available clients
      min_fit_clients=num_clients,
      min_evaluate_clients=num_clients,
      min_available_clients=num_clients,
 
      evaluate_metrics_aggregation_fn=evaluate_metrics_aggregation_fn,  # Add this
       
      on_evaluate_config_fn=get_on_evaluate_config_fn(),
)
      print(f'strategy ggg {strategyi}')

    elif strategy =="moon":
      print(f'strategy of method {strategy}')
      strategyi = MOONStrategy(
        fraction_fit=1.0,  # Train with 50% of available clients
      fraction_evaluate=0.5,  # Evaluate with all available clients
      min_fit_clients=3,
      min_evaluate_clients=2,
      min_available_clients=2,
      evaluate_metrics_aggregation_fn=evaluate_metrics_aggregation_fn,  # Add this

      
      )
    else: 
      print(f'strategy of method {strategy}')
      strategyi = server.GPAFStrategy(
        experiment_name,
        fraction_fit=1.0,  # Ensure all clients participate in training
        #fraction_evaluate=1.0,
        min_fit_clients=num_clients,  # Set minimum number of clients for training
        min_evaluate_clients=num_clients,
        num_classes=9,
       batch_size=batch_size,
     
        #on_fit_config_fn=fit_config_fn,
     
      )

    ######******Configure the server for 5 rounds of training###########
    config = ServerConfig(num_rounds=10)
    return ServerAppComponents(strategy=strategyi, config=config)
 return server_fn

@hydra.main(config_path="conf", config_name="config", version_base=None)
def main(cfg: DictConfig) -> None:
    global experiment_name
    # In your main training script
    visualizer = StructuredFeatureVisualizer(
    num_clients=2,  # your number of clients
    num_classes=9,  # number of classes in your data
    )
    server_fn = get_server_fn()
    # Create mlruns directory
    os.makedirs("mlruns", exist_ok=True)
    
    # Set up MLflow tracking
    mlflow.set_tracking_uri("file://" + os.path.abspath("mlruns"))
    
   
    # print config structured as YAML
    print(OmegaConf.to_yaml(cfg))

    trainloaders, valloaders, testloader=data_load(cfg)
    # Print data distribution before visualization
   
     
    #visualize_intensity_distributions_pathmnist_two_clients(trainloaders, 2) 
    #visualize_class_domain_shift(trainloaders) 
    #visualize_class_domain_shift_pathmnist(trainloaders) 
    #visualizer = LabelDistributionVisualizer(
    #    num_clients=2,
    #    num_classes=9  # For binary classification in breast cancer dataset
    #)
    # Create visualization directory
    #viz_dir = os.path.join(os.getcwd(), 'visualizations')
    # Generate and save visualizations
    #save_path = os.path.join(viz_dir, 'initial_label_distribution.png')
    #client_distributions, global_distribution = visualizer.plot_label_distributions(
    #    trainloaders,
    #    save_path=save_path
    #)
    
    # Log distribution metrics
    #distribution_metrics = visualizer.compute_distribution_metrics(client_distributions)
    #first_batch = next(iter(valloaders[0]))

    # If the batch is a tuple (e.g., input, label), unpack it
    #inputs, labels = first_batch[0], first_batch[1]
    #device = cfg.server_device
    device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
    print(f"Main Server using device: {device}")
 
    if strategy=="gpaf":
      client_fn = gen_client_fn(
        num_clients=cfg.num_clients,
        num_epochs=cfg.num_epochs,
        trainloaders=trainloaders,
        valloaders=valloaders,
        num_rounds=cfg.num_rounds,
        learning_rate=cfg.learning_rate,
        experiment_name=experiment_name,
        strategy=strategy
         ,
        device=device,
       batch_size=cfg.batch_size
       )
    elif strategy =="moon":
      
      # Create the ClientApp
      client_fn = gen_client_fn(
        num_clients=cfg.num_clients,
        num_epochs=cfg.num_epochs,
        trainloaders=trainloaders,
        valloaders=valloaders,
        num_rounds=cfg.num_rounds,
        learning_rate=cfg.learning_rate,
        #change swim or resnet architecture
        experiment_name=experiment_name
        ,strategy=strategy,
        cfg=cfg
         ,
        device=device
       )
    else:
      # Create the ClientApp
      client_fn = gen_client_fn(
        num_clients=cfg.num_clients,
        num_epochs=cfg.num_epochs,
        trainloaders=trainloaders,
        valloaders=valloaders,
        num_rounds=cfg.num_rounds,
        learning_rate=cfg.learning_rate,
        #change swim or resnet architecture
       
        experiment_name=experiment_name
        ,strategy=strategy
 ,
        device=device
       )

    client = ClientApp(client_fn=client_fn)
    
    def get_on_fit_config():
        def fit_config_fn(server_round: int):
            # resolve and convert to python dict
            fit_config: FitConfig = OmegaConf.to_container(  # type: ignore
                cfg.fit_config, resolve=True
            )
            fit_config["curr_round"] = server_round  # add round info
            return fit_config

        return fit_config_fn
    print(f'gafaf : {cfg.client_resources.num_cpus} and {cfg.client_resources.num_cpus}')
   
    # Start simulation
    server= ServerApp(server_fn=server_fn)
    history = run_simulation(
        client_app=client,
        server_app=server ,
          num_supernodes=cfg.num_clients,
      backend_config= {
            "num_cpus": cfg.client_resources.num_cpus,
            "num_gpus": cfg.client_resources.num_gpus,
           "client_resources": {
            "num_cpus": cfg.client_resources.num_cpus,
            "num_gpus": cfg.client_resources.num_gpus,  # ← FIX THIS!
        }
        },
       
      
    )
    # generate plots using the `history`
    
    save_path = HydraConfig.get().runtime.output_dir
     #test model gpaf
    input_dim = 28  # Example: 28x28 images flattened
    hidden_dim = 128
    latent_dim = 64
    num_classes = 9 
    img_shape=(28,28)
    # 1) Device detection
    """
    if strategy=="gpaf":
      encoder = Encoder(latent_dim).to(device)
      classifier = Classifier(latent_dim=64, num_classes=num_classes).to(device)
      decoder = Decoder(latent_dim).to(device)
      for client_id in range(cfg.num_clients):
    
            # Load the saved models for this client
            load_client_model(client_id, encoder, classifier, decoder)
            # Test the client model
            print(f"Testing Client {client_id}")
            test_gpaf(encoder, classifier, testloader, device, num_classes=num_classes)
            # Convert NumpyClient to Client
            
    elif strategy=="moon":
        for client_id in range(cfg.num_clients):
            output_dim=cfg.output_dim
            net = init_net(output_dim)
            # Load the saved models for this client
            load_client_model_moon(client_id, net)
            # Test the client model
            print(f"Testing Client {client_id}")
            test_moon(net, testloader, device,load_model=True, client_id=client_id)
   
    elif strategy=="fedavg":
        for client_id in range(cfg.num_clients):
            output_dim=cfg.output_dim
            net=get_model("resnet")
            # Load the saved models for this client
            load_client_model_moon(client_id, net)
            # Test the client model
            print(f"Testing Client {client_id}")
            test(net, testloader)
  
    #save_results_as_pickle(history, file_path=save_path, extra_results={})
    """
    # Load dataset and select an image from class 0
    """
    root_path = os.getcwd()
    transform = build_transform()
    trainset = BreastMnistDataset(root_path, prefix='train', transform=transform)
    class_0_indices = [i for i, (_, label) in enumerate(trainset) if label == 0]
    selected_idx = class_0_indices[0]  # Take the first image from class 0
    original_img, _ = trainset[selected_idx]

    # Ensure the image is a tensor and has the expected shape (1, H, W)
    if not isinstance(original_img, torch.Tensor):
      original_img = torch.tensor(original_img)
    if original_img.dim() == 2:
      original_img = original_img.unsqueeze(0)  # Add channel dimension if missing

    # Define the clients to display
    client_ids = [0, 1, 2]
    client_labels = ['Client 0 (High-End)', 'Client 1 (Mid-Range)', 'Client 2 (Older Model)']
    transformed_images = []

    # Apply domain shift for each client
    for client_id in client_ids:
      domain_shift = SameModalityDomainShift(client_id=client_id)
      transformed_img = domain_shift.apply_transform(original_img.clone())
      transformed_images.append(transformed_img.squeeze(0))  # Remove channel dim for display

    # Create a figure with subplots
    fig, axes = plt.subplots(1, 3, figsize=(12, 4))
    for ax, img, label in zip(axes, transformed_images, client_labels):
      # Convert tensor to numpy for plotting
      img_np = img.numpy()
      # Display the image
      ax.imshow(img_np, cmap='gray')
      ax.set_title(label, fontsize=12)
      ax.axis('off')

    # Adjust layout and save the figure
    plt.tight_layout()
    plt.savefig('domain_shift_illustration.png', dpi=300, bbox_inches='tight')
    plt.close()
    
    print("Figure saved as 'domain_shift_illustration.png'")
    """

def data_load(cfg: DictConfig):
  device = torch.device("cuda" if torch.cuda.is_available() else "cpu")
  
  trainloaders, valloaders, testloader = load_datasets(
        config=cfg.dataset_config,
        num_clients=cfg.num_clients,
        batch_size=cfg.batch_size,
        domain_shift=True,
        device = device

    )
  return trainloaders, valloaders, testloader   
if __name__ == "__main__":
    
    main()
    
    
