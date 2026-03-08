"""Environment for agent-bandit interactions in Coleman4HCS.

This module contains the `Environment` class which simulates the agent's interactions and
collects results during the reinforcement learning process. The environment provides a
platform where agents learn from interactions with the bandit to make better decisions
over time.

The module also contains the following features:

- Mechanism to reset the environment and agent's memories.
- Ability to run a single experiment or multiple experiments.
- Support for both simple and contextual agents.
- Periodic saving of experiments to handle long-running experiments.
- Facilities for creating and storing results obtained during experiments.
- Support for scenarios with variants, commonly found in Heterogeneous Computing Systems (HCS).
- Helper methods for loading and saving experiment states for recovery purposes.

Classes
-------
Environment
    Represents the learning environment where agents interact with bandits.
"""

import logging
import os
import pickle
import time
import warnings
from pathlib import Path

import numpy as np
import polars as pl

from coleman4hcs.agent import ContextualAgent, SlidingWindowContextualAgent
from coleman4hcs.bandit import EvaluationMetricBandit
from coleman4hcs.scenarios import IndustrialDatasetHCSScenarioProvider, VirtualHCSScenario
from coleman4hcs.utils.monitor import MonitorCollector
from coleman4hcs.utils.monitor_params import CollectParams

Path("backup").mkdir(parents=True, exist_ok=True)

logger = logging.getLogger(__name__)

warnings.simplefilter(action="ignore", category=FutureWarning)


class Environment:
    """The environment class that simulates the agent's interactions and collects results.

    Parameters
    ----------
    agents : list
        List of agent instances participating in the simulation.
    scenario_provider : object
        The scenario provider supplying test case data.
    evaluation_metric : EvaluationMetric
        The evaluation metric used to assess prioritization performance.

    Attributes
    ----------
    agents : list
        List of agent instances.
    scenario_provider : object
        The scenario provider instance.
    evaluation_metric : EvaluationMetric
        The evaluation metric instance.
    monitor : MonitorCollector or None
        Monitor for collecting feedback during the process.
    variant_monitors : dict
        Dictionary of monitors for each variant.
    """

    def __init__(self, agents, scenario_provider, evaluation_metric):
        """Initialize the Environment.

        Parameters
        ----------
        agents : list
            List of agent instances participating in the simulation.
        scenario_provider : object
            The scenario provider supplying test case data.
        evaluation_metric : EvaluationMetric
            The evaluation metric used to assess prioritization performance.
        """
        self.agents = agents
        self.scenario_provider = scenario_provider
        self.evaluation_metric = evaluation_metric
        self.monitor: MonitorCollector = MonitorCollector()
        self.variant_monitors: dict[str, MonitorCollector] = {}
        self.reset()

    def reset(self):
        """Reset the environment for a new simulation."""
        self.reset_agents_memory()
        # Monitor saves the feedback during the process
        self.monitor = MonitorCollector()
        self.variant_monitors = {}

        if (
            isinstance(self.scenario_provider, IndustrialDatasetHCSScenarioProvider)
            and self.scenario_provider.get_total_variants() > 0
        ):
            for variant in self.scenario_provider.get_all_variants():
                self.variant_monitors[variant] = MonitorCollector()

    def reset_agents_memory(self):
        """Reset all agents' memory to an initial state."""
        for agent in self.agents:
            agent.reset()

    def run_single(self, experiment, trials=100, bandit_type=EvaluationMetricBandit, restore=True):
        """Execute a single simulation experiment.

        Parameters
        ----------
        experiment : int
            Current experiment number.
        trials : int, optional
            The max number of scenarios that will be analyzed. Default is 100.
        bandit_type : type, optional
            The bandit class to use. Default is ``EvaluationMetricBandit``.
        restore : bool, optional
            Restore the experiment if it fails (e.g., energy down). Default is True.
        """
        # The agent need to learn from the beginning for each experiment
        self.reset_agents_memory()

        # create a bandit (initially is None to know that is the first bandit
        bandit = None

        # restore to step
        restore_step = 1

        if restore:
            # Restore the experiment from the last backup
            # This is useful for long experiments
            restore_step, self.agents, self.monitor, self.variant_monitors, bandit = self.load_experiment(experiment)
            self.scenario_provider.last_build(restore_step)
            restore_step += 1  # start 1 step after the last build

        # Test Budget percentage
        avail_time_ratio = self.scenario_provider.get_avail_time_ratio()

        # For each "virtual scenario" I must analyse it and evaluate it
        for t, virtual_scenario in enumerate(self.scenario_provider, start=restore_step):
            # The max number of scenarios that will be analyzed
            if t > trials:
                break

            # Time Budget
            available_time = virtual_scenario.get_available_time()
            self.evaluation_metric.update_available_time(available_time)

            # Compute time
            start_bandit = time.time()

            if bandit is None:
                bandit = bandit_type(virtual_scenario.get_testcases(), self.evaluation_metric)
            else:
                # Update bandit (the arms = TC available) for all agents
                bandit.update_arms(virtual_scenario.get_testcases())

            end_bandit = time.time()

            bandit_duration = end_bandit - start_bandit

            # we can analyse the same "moment/scenario t" for "i agents"
            for _, agent in enumerate(self.agents):
                # Update again because the variants
                # each variant has its own test budget size, that is, different from the whole system
                self.evaluation_metric.update_available_time(available_time)

                action, end, exp_name, start = self.run_prioritization(
                    agent, bandit, bandit_duration, experiment, t, virtual_scenario
                )

                # If we are working with HCS scenario and there are variants
                if isinstance(virtual_scenario, VirtualHCSScenario) and len(virtual_scenario.get_variants()) > 0:
                    self.run_prioritization_hcs(
                        agent,
                        action,
                        avail_time_ratio,
                        bandit_duration,
                        end,
                        exp_name,
                        experiment,
                        start,
                        t,
                        virtual_scenario,
                    )

            self.save_periodically(restore, t, experiment, bandit)

    def run_prioritization(  # pylint: disable=too-many-positional-arguments
        self, agent, bandit, bandit_duration, experiment, t, virtual_scenario
    ):
        """Run the prioritization process for a given agent and scenario.

        Parameters
        ----------
        agent : Agent
            The agent that is being used for the prioritization.
        bandit : Bandit
            The bandit mechanism used for choosing actions.
        bandit_duration : float
            Time taken by the bandit process.
        experiment : int
            The current experiment number.
        t : int
            The current step or iteration of the simulation.
        virtual_scenario : VirtualScenario
            The virtual scenario being considered.

        Returns
        -------
        tuple
            A tuple containing the chosen action, the ending time, the
            experiment name, and the starting time.
        """
        # MAB or CMAB
        if type(agent) in [ContextualAgent, SlidingWindowContextualAgent]:
            # For a Contextual agent, we first update the current context information
            agent.update_context(virtual_scenario.get_context_features())
            agent.update_features(virtual_scenario.get_features())

            exp_name = f"{str(agent)}_{virtual_scenario.get_feature_group()}"
        else:
            exp_name = str(agent)

        # Update the bandit inside the agent.
        # This loop also update the actions available for policy choose
        agent.update_bandit(bandit)

        # Compute time
        start = time.time()

        # Choose action (Prioritized Test Suite List) from agent (from current Q estimate)
        action = agent.choose()

        # Pick up reward from bandit for chosen action
        # Submit prioritized test cases for evaluation step the environment and get new measurements
        metric = agent.bandit.pull(action)

        # Update Q action-value estimates (Reward Functions)
        agent.observe(metric)

        # Compute end time
        end = time.time()

        logger.debug(
            "Exp: %s - Ep: %s - Name: %s (%s) - NAPFD/APFDc: %.4f/%.4f",
            experiment,
            t,
            exp_name,
            str(agent.get_reward_function()),
            metric.fitness,
            metric.cost,
        )

        # Collect the data during the experiment
        params = CollectParams(
            scenario_provider=self.scenario_provider,
            available_time=virtual_scenario.get_available_time(),
            experiment=experiment,
            t=t,
            policy=exp_name,
            reward_function=str(agent.get_reward_function()),
            metric=metric,
            total_build_duration=self.scenario_provider.total_build_duration,
            prioritization_time=(end - start) + bandit_duration,
            rewards=np.mean(agent.last_reward),
            prioritization_order=action,
        )

        self.monitor.collect(params)

        return action, end, exp_name, start

    def run_prioritization_hcs(  # pylint: disable=too-many-positional-arguments
        self, agent, action, avail_time_ratio, bandit_duration, end, exp_name, experiment, start, t, virtual_scenario
    ):
        """Run the prioritization process for a given agent and HCS scenario.

        Parameters
        ----------
        agent : Agent
            The agent that is being used for the prioritization.
        action : list of str
            The chosen action by the agent.
        avail_time_ratio : float
            The available time ratio for the experiment.
        bandit_duration : float
            Time taken by the bandit process.
        end : float
            The ending time of the process.
        exp_name : str
            The name of the experiment.
        experiment : int
            The current experiment number.
        start : float
            The starting time of the process.
        t : int
            The current step or iteration of the simulation.
        virtual_scenario : VirtualHCSScenario
            The virtual HCS scenario being considered.
        """
        # Get the variants that exist in the current commit
        variants = virtual_scenario.get_variants()

        # For each variant I will evaluate the impact of the main prioritization
        for variant in variants["Variant"].unique():
            # Get the data from current variant
            df = variants.filter(pl.col("Variant") == variant)

            # Order by the test cases according to the main prioritization
            action_map = {name: idx + 1 for idx, name in enumerate(action)}
            df = df.with_columns([pl.col("Name").replace_strict(action_map, default=0).alias("CalcPrio")])
            df = df.sort("CalcPrio")

            total_build_duration = df["Duration"].sum()
            total_time = total_build_duration * avail_time_ratio

            # Update the available time concerning the variant build duration
            self.evaluation_metric.update_available_time(total_time)

            # Submit prioritized test cases for evaluation step and get new measurements
            self.evaluation_metric.evaluate(df.to_dicts())

            # Save the information (collect the data)
            params = CollectParams(
                scenario_provider=self.scenario_provider,
                available_time=total_time,
                experiment=experiment,
                t=t,
                policy=exp_name,
                reward_function=str(agent.get_reward_function()),
                metric=self.evaluation_metric,
                total_build_duration=total_build_duration,
                prioritization_time=(end - start) + bandit_duration,
                rewards=0,
                prioritization_order=df["Name"].to_list(),
            )

            self.variant_monitors[variant].collect(params)

    def save_periodically(  # pylint: disable=too-many-positional-arguments
        self, restore, t, experiment, bandit, interval=50000
    ):
        """Save the experiment periodically based on a predefined interval.

        Parameters
        ----------
        restore : bool
            Flag to indicate if the experiment should be restored.
        t : int
            The current step or iteration of the simulation.
        experiment : int
            The current experiment number.
        bandit : Bandit
            The current bandit being used in the simulation.
        interval : int, optional
            The interval at which the experiment should be saved. Default is 50000.
        """
        # Save experiment each X builds
        if restore and t % interval == 0:
            self.save_experiment(experiment, t, bandit)

    def run(self, experiments=1, trials=100, bandit_type=EvaluationMetricBandit, restore=True):
        """Execute a simulation over multiple experiments.

        Parameters
        ----------
        experiments : int, optional
            Number of experiments. Default is 1.
        trials : int, optional
            The max number of scenarios that will be analyzed. Default is 100.
        bandit_type : type, optional
            The bandit class to use. Default is ``EvaluationMetricBandit``.
        restore : bool, optional
            Restore the experiment if it fails. Default is True.
        """
        self.reset()

        for exp in range(experiments):
            self.run_single(exp, trials, bandit_type, restore)

    def create_file(self, name):
        """Create a file to store the results obtained during the experiment.

        Parameters
        ----------
        name : str
            The name of the file to store the results.
        """
        self.monitor.create_file(name)

        # If we are working with HCS scenario, we create a file for each variant in a specific directory
        if (
            isinstance(self.scenario_provider, IndustrialDatasetHCSScenarioProvider)
            and self.scenario_provider.get_total_variants() > 0
        ):
            # Ignore the extension
            name = name.split(".csv")[0]
            name = f"{name}_variants"

            Path(name).mkdir(parents=True, exist_ok=True)

            for variant in self.scenario_provider.get_all_variants():
                self.variant_monitors[variant].create_file(
                    f"{name}/{name.split('/')[-1].split('@')[0]}@{variant.replace('/', '-')}.csv"
                )

    def store_experiment(self, csv_file_name):
        """Save the results obtained during the experiment.

        Parameters
        ----------
        csv_file_name : str
            The name of the file to store the results.
        """
        # Collect from temp and save a file (backup and easy sharing/auditing)
        self.monitor.save(csv_file_name)

        if (
            isinstance(self.scenario_provider, IndustrialDatasetHCSScenarioProvider)
            and self.scenario_provider.get_total_variants() > 0
        ):
            # Ignore the extension
            name2 = csv_file_name.split(".csv")[0]
            name2 = f"{name2}_variants"

            Path(name2).mkdir(parents=True, exist_ok=True)

            for variant in self.scenario_provider.get_all_variants():
                # Collect from temp and save a file (backup and easy sharing/auditing)
                self.variant_monitors[variant].save(
                    f"{name2}/{csv_file_name.split('/')[-1].split('@')[0]}@{variant.replace('/', '-')}.csv"
                )

        # Clear experiment
        self.monitor.clear()

    def load_experiment(self, experiment):
        """Load a backup of the experiment.

        Parameters
        ----------
        experiment : int
            The current experiment number.

        Returns
        -------
        tuple
            A tuple containing the restore step, agents, monitor,
            variant monitors, and bandit.
        """
        filename = f"backup/{str(self.scenario_provider)}_ex_{experiment}.p"

        if not os.path.exists(filename):
            return 0, self.agents, self.monitor, self.variant_monitors, None

        with open(filename, "rb") as file:
            return pickle.load(file)

    def save_experiment(self, experiment, t, bandit):
        """Save a backup for the experiment.

        Parameters
        ----------
        experiment : int
            The current experiment number.
        t : int
            The current step or iteration of the simulation.
        bandit : Bandit
            The current bandit being used in the simulation.

        Raises
        ------
        Exception
            If there is an error saving the experiment.
        """
        try:
            filename = f"backup/{str(self.scenario_provider)}_ex_{experiment}.p"
            with open(filename, "wb") as f:
                pickle.dump([t, self.agents, self.monitor, self.variant_monitors, bandit], f)
        except Exception as e:
            logger.error("Error saving the experiment: %s", e)
            raise e
